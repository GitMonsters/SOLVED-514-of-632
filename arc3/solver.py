"""
Game-state-aware solvers for ARC-AGI-3 games.

These solvers access env._game internals to read the full game state,
build navigation graphs, and plan optimal solutions via BFS.
"""

from __future__ import annotations
import copy
import heapq
import logging
import time
from collections import deque
from typing import Optional

import numpy as np
from arcengine import GameAction, GameState, ActionInput

logger = logging.getLogger("arc3.solver")

AMAP = {a.value: a for a in GameAction}

# LS20 action names → GameAction (ACTION1=UP, ACTION2=DOWN, ACTION3=LEFT, ACTION4=RIGHT)
LS20_ACT = {
    'U': GameAction.ACTION1,
    'D': GameAction.ACTION2,
    'L': GameAction.ACTION3,
    'R': GameAction.ACTION4,
}

# Legacy integer mapping kept for other uses
LS20_DIRS = {
    1: (0, -1),   # UP
    2: (0, 1),    # DOWN
    3: (-1, 0),   # LEFT
    4: (1, 0),    # RIGHT
}


class Ls20Solver:
    """Solves LS20 (9607627b) levels: navigate player to match shape/color/rotation targets.

    Game mechanics (full model):
    - Player (gudziatsk) moves on a grid of cells sized gisrhqpee × tbwnoxqgc pixels.
    - txnfzvzetn fires BEFORE the player moves, processing sprites at the destination:
        * "ihdgageizm" wall → blocked (break)
        * "rjlbuycveu" unmatched target → blocked (continue, other sprites still fire)
        * "npxgalaybz" pickup → refills step counter
        * "ttfwljgohq" shape changer → fwckfzsyc = (fwckfzsyc+1) % n_shapes
        * "soyhouuebz" color changer → hiaauhahz = (hiaauhahz+1) % n_colors
        * "rhsxkxzdjz" rot changer → cklxociuu = (cklxociuu+1) % 4
    - After moving, "gbvqrjtaqo" pushers (twkzhcfelv) may slide the player some cells.
      txnfzvzetn fires AGAIN at the pushed destination.
    - pbznecvnfr() checks all targets: if player is on target AND state matches → done.
    """

    def __init__(self, env, verbose: bool = False):
        self.env = env
        self.verbose = verbose

    @property
    def game(self):
        return self.env._game

    def _build_level_info(self) -> dict:
        """Extract all relevant level info for the BFS."""
        g = self.game
        level = g.current_level
        step_x = g.gisrhqpee
        step_y = g.tbwnoxqgc

        # Grid bounds from all sprites
        xs = [s.x for s in level._sprites]
        ys = [s.y for s in level._sprites]
        if not xs:
            return {}
        min_x, max_x = min(xs), max(xs)
        min_y, max_y = min(ys), max(ys)

        # Player grid alignment base
        base_x = g.gudziatsk.x % step_x
        base_y = g.gudziatsk.y % step_y

        def trigger_cells(sx: int, sy: int, sw: int, sh: int):
            """Grid-aligned positions where this sprite's bbox overlaps player bbox."""
            cells = []
            # nx range: sx < nx + step_x AND sx + sw > nx
            # → nx in (sx - step_x, sx + sw)  (exclusive)
            x_lo = sx - step_x + 1
            x_hi = sx + sw - 1
            # Snap x_lo up to grid alignment
            first_x = x_lo + (base_x - x_lo % step_x) % step_x
            for nx in range(first_x, x_hi + 1, step_x):
                if nx < min_x or nx > max_x:
                    continue
                y_lo = sy - step_y + 1
                y_hi = sy + sh - 1
                first_y = y_lo + (base_y - y_lo % step_y) % step_y
                for ny in range(first_y, y_hi + 1, step_y):
                    if ny < min_y or ny > max_y:
                        continue
                    cells.append((nx, ny))
            return cells

        # Walls
        walls = set()
        for s in level._sprites:
            if s.tags and "ihdgageizm" in s.tags:
                for cell in trigger_cells(s.x, s.y, s.width, s.height):
                    walls.add(cell)

        # Pusher effects: (cell) -> final_cell
        push_map = {}
        for belt in g.hasivfwip:
            dist = belt.ullzqnksoj(None)
            if dist <= 0:
                continue
            bw = belt.sprite.width
            bh = belt.sprite.height
            target_x = belt.start_x + belt.dx * bw * dist
            target_y = belt.start_y + belt.dy * bh * dist
            dx_push = target_x - belt.start_x
            dy_push = target_y - belt.start_y
            for cell in trigger_cells(belt.sprite.x, belt.sprite.y, bw, bh):
                push_map[cell] = (cell[0] + dx_push, cell[1] + dy_push)

        # Resolve push chains
        for pos in list(push_map):
            dest = push_map[pos]
            seen = {pos}
            while dest in push_map and dest not in seen:
                seen.add(dest)
                dest = push_map[dest]
            push_map[pos] = dest

        # Which modifiers are carried by walkers (and thus have dynamic positions)?
        walker_carried = set()  # sprite ids of walker-carried modifier sprites
        walker_mods = []  # list of {type, path, period}
        MOD_TAGS = {"ttfwljgohq": "shape", "soyhouuebz": "color", "rhsxkxzdjz": "rot"}

        for walker in g.wsoslqeku:
            sp = walker._sprite
            if not sp.tags:
                continue
            mod_type = next((MOD_TAGS[t] for t in sp.tags if t in MOD_TAGS), None)
            if mod_type is None:
                continue
            walker_carried.add(id(sp))

            # Simulate walker to find its cycle
            saved_dir = walker._dir
            saved_x, saved_y = sp.x, sp.y
            path = [(sp.x, sp.y)]  # path[0] = initial position (before any step)
            states_seen = {(walker._dir, sp.x, sp.y): 0}
            period = None
            for k in range(500):
                walker.step()
                state = (walker._dir, sp.x, sp.y)
                if state in states_seen:
                    period = k + 1 - states_seen[state]
                    break
                states_seen[state] = k + 1
                path.append((sp.x, sp.y))
            if period is None:
                period = len(path)
            # Restore walker state
            walker._dir = saved_dir
            sp.set_position(saved_x, saved_y)
            walker._undo_x = None
            walker._undo_y = None
            walker._undo_dir = None
            # Trim path to one full cycle starting from initial
            cycle_start = len(path) - period
            if cycle_start < 0:
                cycle_start = 0
            # path[0] is position before step 1; path[p] is position AFTER p steps
            walker_mods.append({'type': mod_type, 'path': path, 'period': period})

        # Compute LCM of all walker periods (for step_phase in BFS)
        from math import gcd
        def lcm(a, b): return a * b // gcd(a, b)
        period_lcm = 1
        for wm in walker_mods:
            period_lcm = lcm(period_lcm, wm['period'])

        # Static modifiers (non-walker-carried)
        modifiers = {}  # (x,y) -> list of modifier types
        MOD_ORDER = [("ttfwljgohq", "shape"), ("soyhouuebz", "color"), ("rhsxkxzdjz", "rot")]
        for s in level._sprites:
            if not s.tags or id(s) in walker_carried:
                continue
            for tag, mtype in MOD_ORDER:
                if tag in s.tags:
                    # Only use mrznumynfe-compatible matching: sprite.x in [px, px+step_x) AND ...
                    # For non-walker sprites, compute trigger cells (at initial position)
                    for cell in trigger_cells(s.x, s.y, s.width, s.height):
                        modifiers.setdefault(cell, []).append(mtype)

        # phase_mods[p] = modifiers dict valid when walker is at phase p
        # (phase = number of steps taken so far, before this step)
        # During step n (1-indexed), walker is at phase n → use phase_mods[n % period_lcm]
        # But we need "mods AFTER walker advances on step n" = path[n]
        # Simplify: phase_mods[p] = static_modifiers + walker positions at path[p]
        phase_mods = []
        for p in range(period_lcm):
            pm = {k: list(v) for k, v in modifiers.items()}  # copy static
            for wm in walker_mods:
                wx, wy = wm['path'][p % len(wm['path'])]
                # Walker's sprite.x is its top-left; it fires when player's x == wx AND y == wy
                pm.setdefault((wx, wy), []).append(wm['type'])
            phase_mods.append(pm)

        # If no walkers, period_lcm=1 and phase_mods[0] == modifiers

        # Pickups: grid cells that trigger them (one-time use)
        pickups = set()
        for s in level._sprites:
            if s.tags and "npxgalaybz" in s.tags:
                for cell in trigger_cells(s.x, s.y, s.width, s.height):
                    pickups.add(cell)

        # Targets (only unsolved ones remain in level._sprites)
        targets = []
        for i in range(len(g.plrpelhym)):
            targets.append({
                'idx': i,
                'pos': (g.plrpelhym[i].x, g.plrpelhym[i].y),
                'shape': g.ldxlnycps[i],
                'color': g.yjdexjsoa[i],
                'rot': g.ehwheiwsk[i],
                'done': g.lvrnuajbl[i],
            })
        target_by_pos = {t['pos']: t for t in targets if not t['done']}

        # Step budget
        ui = g._step_counter_ui
        try:
            decrement = ui.efipnixsvl
            budget = ui.osgviligwp // decrement if decrement > 0 else ui.osgviligwp
        except AttributeError:
            budget = ui.osgviligwp

        return {
            'step_x': step_x, 'step_y': step_y,
            'walls': walls, 'push_map': push_map,
            'modifiers': modifiers, 'phase_mods': phase_mods, 'period_lcm': period_lcm,
            'pickups': pickups,
            'targets': targets, 'target_by_pos': target_by_pos,
            'player': (g.gudziatsk.x, g.gudziatsk.y),
            'state': (g.fwckfzsyc, g.hiaauhahz, g.cklxociuu),
            'done': tuple(g.lvrnuajbl),
            'n_shapes': len(g.ijessuuig),
            'n_colors': len(g.tnkekoeuk),
            'budget': budget,
            'bounds': (min_x, max_x, min_y, max_y),
        }

    def _apply_modifiers(self, pos: tuple, si: int, ci: int, ri: int,
                         modifiers: dict, n_shapes: int, n_colors: int) -> tuple:
        for mtype in modifiers.get(pos, []):
            if mtype == 'shape':
                si = (si + 1) % n_shapes
            elif mtype == 'color':
                ci = (ci + 1) % n_colors
            elif mtype == 'rot':
                ri = (ri + 1) % 4
        return si, ci, ri

    def solve_level(self) -> Optional[list]:
        """BFS over (pos, shape, color, rot, done_mask) game states.
        
        Models pushers, target blocking, and modifier cycling correctly.
        """
        info = self._build_level_info()
        if not info:
            return []

        targets = info['targets']
        unsolved = [t for t in targets if not t['done']]
        if not unsolved:
            return []

        walls = info['walls']
        push_map = info['push_map']
        phase_mods = info['phase_mods']   # list indexed by step_phase
        period_lcm = info['period_lcm']
        pickups = info['pickups']
        target_by_pos = info['target_by_pos']
        n_shapes = info['n_shapes']
        n_colors = info['n_colors']
        budget = info['budget']
        step_x = info['step_x']
        step_y = info['step_y']
        min_x, max_x, min_y, max_y = info['bounds']

        px0, py0 = info['player']
        s0, c0, r0 = info['state']
        done0 = info['done']

        n_unsolved = len(unsolved)
        # Map unsolved target index → bit position
        target_bit = {t['idx']: i for i, t in enumerate(unsolved)}
        all_done_mask = (1 << n_unsolved) - 1

        # Initial done mask
        init_mask = 0
        for t in unsolved:
            if t['done']:
                init_mask |= (1 << target_bit[t['idx']])

        DIRS = [
            ('U', 0, -step_y),
            ('D', 0,  step_y),
            ('L', -step_x, 0),
            ('R',  step_x, 0),
        ]

        def transition(px, py, si, ci, ri, done_mask, act_dx, act_dy, step_phase):
            """Apply one action. Returns (new_px, new_py, new_si, new_ci, new_ri, new_done_mask)
            or None if move is blocked."""
            nx, ny = px + act_dx, py + act_dy

            # Wall blocking
            if (nx, ny) in walls:
                return None

            # Out of bounds guard
            if not (min_x <= nx <= max_x and min_y <= ny <= max_y):
                return None

            # Walker advances to next phase during this step
            next_phase = (step_phase + 1) % period_lcm
            mods = phase_mods[next_phase]

            # Apply modifiers at destination (shape/color/rot changers)
            new_si, new_ci, new_ri = self._apply_modifiers(
                (nx, ny), si, ci, ri, mods, n_shapes, n_colors)

            # Target blocking: if destination has an unmatched target, blocked
            tgt = target_by_pos.get((nx, ny))
            if tgt is not None and not (done_mask & (1 << target_bit[tgt['idx']])):
                if not (new_si == tgt['shape'] and new_ci == tgt['color'] and new_ri == tgt['rot']):
                    # Check with PRE-modifier state too
                    if not (si == tgt['shape'] and ci == tgt['color'] and ri == tgt['rot']):
                        return None  # blocked regardless

            # Apply pusher effect
            final_pos = push_map.get((nx, ny), (nx, ny))
            if final_pos != (nx, ny):
                # Modifiers fire again at pushed destination (walker doesn't advance again)
                new_si, new_ci, new_ri = self._apply_modifiers(
                    final_pos, new_si, new_ci, new_ri, mods, n_shapes, n_colors)

            fpx, fpy = final_pos

            # Update done mask: check if player is on a target with matching state
            new_done_mask = done_mask
            tgt2 = target_by_pos.get((fpx, fpy))
            if tgt2 is not None:
                bit = 1 << target_bit[tgt2['idx']]
                if not (new_done_mask & bit):
                    if new_si == tgt2['shape'] and new_ci == tgt2['color'] and new_ri == tgt2['rot']:
                        new_done_mask |= bit

            return (fpx, fpy, new_si, new_ci, new_ri, new_done_mask)

        # BFS — state includes pickups_used_mask, steps_since_last_refuel, and step_phase
        pickup_list = sorted(pickups)
        pickup_bit = {pos: i for i, pos in enumerate(pickup_list)}
        full_budget = budget

        # BFS state: (px, py, si, ci, ri, done_mask, pickups_used_mask, step_phase)
        # Extra per-state value: steps_since_refuel (minimize = more budget remaining)
        initial_state = (px0, py0, s0, c0, r0, init_mask, 0, 0)  # last 2 = pmask, phase
        visited = {initial_state: 0}  # state -> min steps_since_refuel
        queue = deque([(initial_state, [], 0)])

        while queue:
            (px, py, si, ci, ri, dmask, pmask, sp_phase), acts, srf = queue.popleft()

            if visited.get((px, py, si, ci, ri, dmask, pmask, sp_phase), full_budget + 1) < srf:
                continue

            if srf >= full_budget:
                continue

            for act_name, act_dx, act_dy in DIRS:
                result = transition(px, py, si, ci, ri, dmask, act_dx, act_dy, sp_phase)
                if result is None:
                    continue
                fpx, fpy, new_si, new_ci, new_ri, new_dmask = result
                new_srf = srf + 1
                new_phase = (sp_phase + 1) % period_lcm

                # Check if landing on an uncollected pickup → refuel
                new_pmask = pmask
                fpos = (fpx, fpy)
                if fpos in pickup_bit:
                    bit = 1 << pickup_bit[fpos]
                    if not (pmask & bit):
                        new_pmask = pmask | bit
                        new_srf = 0  # Reset step counter

                if new_srf >= full_budget:
                    continue

                if new_dmask == all_done_mask:
                    return acts + [act_name]

                new_state = (fpx, fpy, new_si, new_ci, new_ri, new_dmask, new_pmask, new_phase)
                prev_srf = visited.get(new_state, full_budget + 1)
                if new_srf < prev_srf:
                    visited[new_state] = new_srf
                    queue.append((new_state, acts + [act_name], new_srf))

        if self.verbose:
            logger.info(f"LS20 BFS: no solution in budget={full_budget} steps, "
                       f"explored {len(visited)} states")
        return []


class Vc33Solver:
    """Solves VC33 levels using BFS with deepcopy state management."""

    def __init__(self, env, verbose: bool = False):
        self.env = env
        self.verbose = verbose

    @property
    def game(self):
        return self.env._game

    def _build_display_map(self) -> dict[tuple[int, int], tuple[int, int]]:
        """Build grid→display coordinate mapping for click actions."""
        cam = self.game.camera
        mapping = {}
        for dx in range(64):
            for dy in range(64):
                r = cam.display_to_grid(dx, dy)
                if r and r not in mapping:
                    mapping[r] = (dx, dy)
        return mapping

    def _get_clickable(self, g, display_map: dict) -> list[tuple[int, int, str, int, int]]:
        """Get all clickable display coords with labels and grid positions.
        
        Returns list of (display_x, display_y, label, grid_x, grid_y).
        """
        level = g.current_level
        clicks = []
        seen = set()
        for s in level.get_sprites_by_tag('ZGd'):
            gpos = (s.x, s.y)
            if gpos not in seen and gpos in display_map:
                dx, dy = display_map[gpos]
                clicks.append((dx, dy, f'ZGd({s.x},{s.y})', s.x, s.y))
                seen.add(gpos)
        for s in level.get_sprites_by_tag('zHk'):
            gpos = (s.x, s.y)
            if gpos not in seen and gpos in display_map and g.krt(s):
                dx, dy = display_map[gpos]
                clicks.append((dx, dy, f'zHk({s.x},{s.y})', s.x, s.y))
                seen.add(gpos)
        return clicks

    def _state_key(self, g) -> tuple:
        """Hash the game state for BFS visited tracking."""
        level = g.current_level
        parts = []
        for s in sorted(level.get_sprites_by_tag('HQB'), key=lambda s: s.name):
            parts.append(('H', s.x, s.y))
        for s in sorted(level.get_sprites_by_tag('rDn'), key=lambda s: s.name):
            parts.append(('T', s.x, s.y, s.width, s.height))
        return tuple(parts)

    def _apply_click(self, dx: int, dy: int):
        """Apply a single click via env.step (for replay only)."""
        env = self.env
        obs = env.step(AMAP[6], data={'x': dx, 'y': dy})
        g = env._game
        while g.vai is not None:
            obs = env.step(AMAP[6], data={'x': -1, 'y': -1})
            g = env._game
        return obs

    def _apply_direct(self, g, gx: int, gy: int) -> bool:
        """Apply click directly on game object (no env.step). For BFS search."""
        sprite = g.current_level.get_sprite_at(gx, gy)
        if not sprite:
            return False

        if "ZGd" in sprite.tags:
            g.ccl(sprite)
            return True
        elif "zHk" in sprite.tags:
            if g.krt(sprite):
                vai = g.teu(sprite)
                # Instant-resolve animation: set sprites to final positions
                if vai:
                    for anim_step in vai.lph:
                        anim_step.cab.set_position(anim_step.shl[0], anim_step.shl[1])
                    g.vai = None
                    g.jcy()
                for yps in g.current_level.get_sprites_by_tag("rlV"):
                    yps.set_visible(False)
                return True
        return False

    def _heuristic(self, g) -> int:
        """Estimate remaining clicks needed to win. Admissible for A*."""
        level = g.current_level
        hqbs = level.get_sprites_by_tag('HQB')
        fzks = level.get_sprites_by_tag('fZK')
        rdns = level.get_sprites_by_tag('rDn')
        uxgs = level.get_sprites_by_tag('UXg')
        oro_mag = max(abs(g.oro[0]), abs(g.oro[1]), 1)

        total = 0
        for dds in hqbs:
            AkL = int(dds.pixels[-1, -1])
            best = 200
            for yas in fzks:
                if AkL not in yas.pixels:
                    continue
                d = abs(g.ebl(dds) - g.ebl(yas))
                iZX = [mdf for mdf in uxgs if mdf.collides_with(yas)]
                if iZX:
                    lzS = [avz for avz in rdns if g.gdu(dds, avz)]
                    if lzS:
                        zGp = g.suo(lzS[0])
                        if iZX[0] not in zGp:
                            d += 10  # wrong track penalty
                best = min(best, d)
            total += best
        return total // oro_mag

    def _solve_symbolic(self, grid_seq: list[tuple[int, int]],
                        display_map: dict) -> Optional[list[tuple[int, int, str]]]:
        """Verify and convert a symbolic grid-coord solution to display coords.
        
        Runs the sequence on a deepcopy to confirm it wins, then returns
        the display-coord solution for replay via env.step.
        """
        g = self.env._game
        g_test = copy.deepcopy(g)
        result = []
        for gx, gy in grid_seq:
            dpos = display_map.get((gx, gy))
            if dpos is None:
                return None
            sprite = g_test.current_level.get_sprite_at(gx, gy)
            label = sprite.name if sprite else f"({gx},{gy})"
            self._apply_direct(g_test, gx, gy)
            result.append((dpos[0], dpos[1], label))
            if g_test.gug():
                if self.verbose:
                    logger.info(f"  Symbolic solved: {len(result)} clicks")
                return result
        return None

    def _l6_sequence(self) -> list[tuple[int, int]]:
        """Grid-coordinate sequence for VC33 L6 (5-track, 3-HQB puzzle)."""
        seq = []
        seq += [(16, 0)] * 10   # HMp→RmM transfer x10
        seq += [(16, 24)]       # wmR→RmM transfer x1
        seq += [(14, 30)]       # swap wmR↔RmM (moves ChX to RmM)
        seq += [(12, 0)] * 10   # RmM→HMp transfer x10
        seq += [(34, 0)]        # RmM→HfU transfer x1
        seq += [(32, 8)]        # swap RmM↔HfU (ChX→HfU, VAJ→RmM)
        seq += [(16, 0)] * 10   # HMp→RmM transfer x10
        seq += [(30, 24)] * 2   # AEF→RmM transfer x2
        seq += [(34, 0)]        # RmM→HfU transfer x1
        seq += [(14, 30)]       # swap wmR↔RmM (VAJ→wmR)
        seq += [(32, 30)]       # swap RmM↔AEF (PPS→RmM)
        seq += [(12, 24)] * 6   # RmM→wmR transfer x6
        seq += [(34, 0)] * 4    # RmM→HfU transfer x4
        return seq

    def solve_level(self, max_depth: int = 100, max_nodes: int = 200000,
                    timeout: float = 300.0) -> Optional[list[tuple[int, int, str]]]:
        """A* search to find click sequence that wins the current level.
        
        Uses deepcopy + direct game method calls (no env.step) during search.
        Returns click sequence as (display_x, display_y, label) for replay.
        Falls back to symbolic solver for complex levels (e.g. L6).
        """
        g = self.env._game
        level_idx = g.level_index
        display_map = self._build_display_map()

        # Try symbolic solver first for complex levels (much faster than A*)
        sym_seq = self._l6_sequence()
        sym_sol = self._solve_symbolic(sym_seq, display_map)
        if sym_sol:
            return sym_sol

        initial_clicks = self._get_clickable(g, display_map)
        n_clickable = len(initial_clicks)
        if self.verbose:
            logger.info(f"VC33 L{level_idx}: {n_clickable} clickable, budget={g.vrr.lpw}")

        initial_sk = self._state_key(g)
        initial_h = self._heuristic(g)
        initial_game = copy.deepcopy(g)

        # Use A* for complex levels, plain BFS for simple ones
        use_astar = n_clickable > 5 or initial_h > 5

        counter = 0
        visited = {initial_sk}
        nodes = 0
        t0 = time.time()

        if use_astar:
            pq = [(initial_h, counter, initial_game, [])]
            while pq and time.time() - t0 < timeout:
                f, _, game_copy, seq = heapq.heappop(pq)
                nodes += 1
                if nodes > max_nodes or len(seq) >= max_depth:
                    if len(seq) >= max_depth:
                        continue
                    break

                clicks = self._get_clickable(game_copy, display_map)

                for dx, dy, label, gx, gy in clicks:
                    g_child = copy.deepcopy(game_copy)
                    self._apply_direct(g_child, gx, gy)

                    if g_child.gug():
                        result = seq + [(dx, dy, label)]
                        if self.verbose:
                            logger.info(f"  A* solved: {len(result)} clicks ({nodes} nodes, {time.time()-t0:.1f}s)")
                        return result

                    sk = self._state_key(g_child)
                    if sk not in visited:
                        visited.add(sk)
                        h = self._heuristic(g_child)
                        g_cost = len(seq) + 1
                        counter += 1
                        heapq.heappush(pq, (g_cost + h, counter, g_child, seq + [(dx, dy, label)]))
        else:
            queue = deque([(initial_game, [])])
            while queue and time.time() - t0 < timeout:
                game_copy, seq = queue.popleft()
                nodes += 1
                if nodes > max_nodes or len(seq) >= max_depth:
                    if len(seq) >= max_depth:
                        continue
                    break

                clicks = self._get_clickable(game_copy, display_map)

                for dx, dy, label, gx, gy in clicks:
                    g_child = copy.deepcopy(game_copy)
                    self._apply_direct(g_child, gx, gy)

                    if g_child.gug():
                        result = seq + [(dx, dy, label)]
                        if self.verbose:
                            logger.info(f"  BFS solved: {len(result)} clicks ({nodes} nodes, {time.time()-t0:.1f}s)")
                        return result

                    sk = self._state_key(g_child)
                    if sk not in visited:
                        visited.add(sk)
                        queue.append((g_child, seq + [(dx, dy, label)]))

        if self.verbose:
            logger.info(f"  No solution: {nodes} nodes, {len(visited)} states, {time.time()-t0:.1f}s")
        return None


class Tn36Solver:
    """Solves TN36 levels - program-based position/rotation/scale puzzle.

    Strategy: enumerate all possible programs (4^N combinations), simulate each
    by directly calling otrzjnmayi/rotate/adjust_scale on the LIVE game panel
    (no deepcopy — lambdas in dfguzecnsr break under deepcopy due to closure capture).
    For each program: reset piece → apply ops → check win condition.
    Then generate click sequence to set the winning program and click run.
    """

    def __init__(self, env, verbose: bool = False):
        self.env = env
        self.verbose = verbose

    @property
    def game(self):
        return self.env._game

    def _build_display_map(self) -> dict[tuple[int, int], tuple[int, int]]:
        """Build grid→display coordinate mapping."""
        cam = self.game.camera
        mapping: dict[tuple[int, int], tuple[int, int]] = {}
        for dx in range(64):
            for dy in range(64):
                r = cam.display_to_grid(dx, dy)
                if r and r not in mapping:
                    mapping[r] = (dx, dy)
        return mapping

    def _is_win(self, g=None) -> bool:
        if g is None:
            g = self.game
        if getattr(g, 'nyhaiggftp', False):
            return True
        tx = getattr(g, 'fdksqlmpki', None)
        return bool(tx and getattr(tx, 'vklyonlcrw', False))

    def _get_panel(self):
        return self.game.fdksqlmpki.bzirenxmrg

    def _simulate_program(self, program: list[int]) -> tuple:
        """Reset piece to start, apply program ops, return final (x,y,rot,scale,color).
        
        Works on the LIVE game panel — no deepcopy needed since we reset after.
        """
        panel = self._get_panel()
        panel.olrpupaury()
        src = panel.htntnzkbzu
        for op in program:
            fn = panel.okllwtboml.get(op)
            if fn:
                fn()
        return (src.x, src.y, src.rotation, src.scale, src.sjmtdfxdrc)

    def _apply_op_from_state(self, state: tuple, op: int,
                              op_idx: Optional[int] = None,
                              num_slots: Optional[int] = None) -> Optional[tuple]:
        """Apply one op to piece from given (x,y,rot,scale,color) state.

        op_idx / num_slots: when provided, simulates the jmwdvdqntf() kill-zone
        toggle that fires after op[op_idx] when op_idx % 3 == 2 and it is not
        the last op.  Kill zones are always left invisible after this call so
        that subsequent BFS calls start from a consistent base state.

        Returns None if the op kills the piece.
        """
        panel = self._get_panel()
        src = panel.htntnzkbzu
        x, y, rot, scale, color = state

        # Set kill-zone visibility to the state that should exist BEFORE this op.
        # Each toggle fires after ops whose index satisfies i%3==2 and i<num_slots-1.
        kz_list = getattr(panel, 'ekdwmirldx', [])
        if op_idx is not None and num_slots is not None and kz_list:
            kz_vis = False
            for i in range(op_idx):
                if i % 3 == 2 and i < num_slots - 1:
                    kz_vis = not kz_vis
            for kz in kz_list:
                kz.set_visible(kz_vis)

        # Restore piece to alive state before setting position
        if not src.brvmvgfchj:
            src.lkmgpsdbrr()
        src.set_position(x, y)
        src.set_rotation(rot)
        src.set_scale(scale)
        src.knfgrcbayu(color)
        fn = panel.okllwtboml.get(op)
        if fn:
            fn()

        # Check if the op killed the piece (walked into a kill zone during movement)
        if not src.brvmvgfchj:
            src.lkmgpsdbrr()
            if kz_list:
                for kz in kz_list:
                    kz.set_visible(False)
            return None

        # Simulate jmwdvdqntf(): toggle kill zones after op if applicable
        if op_idx is not None and num_slots is not None and kz_list:
            if op_idx % 3 == 2 and op_idx < num_slots - 1:
                for kz in kz_list:
                    kz.set_visible(not kz.is_visible)
                # Check if piece is now sitting on a now-visible kill zone
                for kz in kz_list:
                    if kz.is_visible and kz.collides_with(src):
                        src.qobvpoiega()
                        break
                if not src.brvmvgfchj:
                    src.lkmgpsdbrr()
                    for kz in kz_list:
                        kz.set_visible(False)
                    return None

        # Always reset kill zones to invisible so next BFS call starts clean
        if kz_list:
            for kz in kz_list:
                kz.set_visible(False)

        return (src.x, src.y, src.rotation, src.scale, src.sjmtdfxdrc)

    def _get_target_state(self) -> Optional[tuple]:
        panel = self._get_panel()
        tgt = getattr(panel, 'aqszntqeae', None)
        if tgt is None:
            return None
        return (tgt.x, tgt.y, getattr(tgt, 'rotation', 0), getattr(tgt, 'scale', 1),
                tgt.sjmtdfxdrc)

    def _get_checkpoints(self) -> list[tuple[int, int, int]]:
        """Return list of checkpoint (x, y, scale) from the player panel."""
        panel = self._get_panel()
        return [
            (sz.axbjgpzkyi.x, sz.axbjgpzkyi.y, sz.axbjgpzkyi.scale)
            for sz in getattr(panel, 'wgzwawbgew', [])
        ]

    def _find_checkpoint_programs(
        self, timeout: float = 50.0
    ) -> Optional[tuple[list[int], list[int]]]:
        """Find two programs (P1, P2) for a checkpoint two-run solution.

        P1: from start → lands on checkpoint (position/scale match triggers save).
        P2: from checkpoint state → reaches target.
        Returns (P1_padded, P2_padded) or None if not found within timeout.
        """
        from collections import deque

        panel = self._get_panel()
        tgt = self._get_target_state()
        if tgt is None:
            return None

        checkpoints = self._get_checkpoints()  # [(x, y, scale), ...]
        if not checkpoints:
            return None
        cp_set = {(x, y): sc for x, y, sc in checkpoints}

        src = panel.htntnzkbzu
        panel.olrpupaury()
        start = (src.x, src.y, src.rotation, src.scale, src.sjmtdfxdrc)
        num_slots = len(panel.ukwrvhanub.pfyayhyovw)
        valid_ops = sorted(panel.okllwtboml.keys())
        t0 = time.time()

        # Phase 1 BFS: find 6-op programs that end at a checkpoint
        # State: (x, y, rotation, scale, color)
        visited1: dict[tuple, int] = {start: 0}
        queue1: deque = deque([(start, [])])
        p1_results: list[tuple[list[int], tuple]] = []  # (ops_padded, checkpoint_state)

        while queue1 and time.time() - t0 < timeout * 0.6:
            cur_state, ops_so_far = queue1.popleft()
            depth = len(ops_so_far)
            if depth >= num_slots:
                continue
            for op in valid_ops:
                next_state = self._apply_op_from_state(cur_state, op, op_idx=depth, num_slots=num_slots)
                if next_state is None:
                    continue
                new_ops = ops_so_far + [op]
                new_depth = len(new_ops)

                # Check if full program ends on a checkpoint
                if new_depth == num_slots:
                    xy = (next_state[0], next_state[1])
                    if xy in cp_set and cp_set[xy] == next_state[3]:  # scale matches
                        padded = new_ops  # already full length
                        p1_results.append((padded, next_state))
                    continue  # don't queue states at max depth

                if next_state not in visited1 or visited1[next_state] > new_depth:
                    visited1[next_state] = new_depth
                    queue1.append((next_state, new_ops))

        panel.olrpupaury()
        if not p1_results:
            return None

        # Phase 2 BFS: from each checkpoint state, find a program reaching target
        for p1, cp_state in p1_results:
            if time.time() - t0 > timeout - 1:
                break

            visited2: dict[tuple, int] = {cp_state: 0}
            queue2: deque = deque([(cp_state, [])])
            found_p2: Optional[list[int]] = None

            while queue2 and time.time() - t0 < timeout - 0.5:
                cur_state, ops_so_far = queue2.popleft()
                depth = len(ops_so_far)
                if depth >= num_slots:
                    continue
                for op in valid_ops:
                    next_state = self._apply_op_from_state(cur_state, op, op_idx=depth, num_slots=num_slots)
                    if next_state is None:
                        continue
                    new_ops = ops_so_far + [op]
                    new_depth = len(new_ops)
                    if next_state == tgt:
                        found_p2 = new_ops + [0] * (num_slots - len(new_ops))
                        break
                    if next_state not in visited2 or visited2[next_state] > new_depth:
                        visited2[next_state] = new_depth
                        if new_depth < num_slots:
                            queue2.append((next_state, new_ops))
                if found_p2:
                    break

            if found_p2:
                panel.olrpupaury()
                return (p1, found_p2)

        panel.olrpupaury()
        return None

    def _find_winning_program(self, timeout: float = 50.0) -> Optional[list[int]]:
        """BFS over piece states to find a program that achieves the target state.
        
        State = (x, y, rotation, scale, color). BFS expands one op per step.
        Much more efficient than brute-force enumeration when slots have many toggles.
        """
        from collections import deque
        panel = self._get_panel()
        tgt = self._get_target_state()
        if tgt is None:
            return None

        src = panel.htntnzkbzu
        panel.olrpupaury()
        start = (src.x, src.y, src.rotation, src.scale, src.sjmtdfxdrc)
        num_slots = len(panel.ukwrvhanub.pfyayhyovw)
        valid_ops = sorted(panel.okllwtboml.keys())

        t0 = time.time()

        if start == tgt:
            panel.olrpupaury()
            return [0] * num_slots

        # BFS: (piece_state, ops_used)
        # visited maps piece_state → minimum steps to reach it
        visited: dict[tuple, int] = {start: 0}
        queue: deque[tuple] = deque([(start, [])])

        while queue:
            if time.time() - t0 > timeout:
                break
            cur_state, ops_so_far = queue.popleft()
            depth = len(ops_so_far)
            if depth >= num_slots:
                continue
            for op in valid_ops:
                next_state = self._apply_op_from_state(cur_state, op, op_idx=depth, num_slots=num_slots)
                if next_state is None:
                    continue  # piece was killed by kill zone, skip
                new_ops = ops_so_far + [op]
                if next_state == tgt:
                    panel.olrpupaury()
                    # Pad remaining slots with no-op (0)
                    return new_ops + [0] * (num_slots - len(new_ops))
                new_depth = len(new_ops)
                if next_state not in visited or visited[next_state] > new_depth:
                    visited[next_state] = new_depth
                    if new_depth < num_slots:
                        queue.append((next_state, new_ops))

        panel.olrpupaury()
        return None

    def _clicks_to_set_program(self, target_program: list[int],
                               display_map: dict) -> list[tuple[int, int, str, int, int]]:
        """Generate click sequence to change current program to target_program.
        
        Uses toggle button positions from slot objects directly,
        targeting only the PLAYER panel's slots (not the reference panel).
        """
        panel = self._get_panel()
        slots = panel.ukwrvhanub.pfyayhyovw
        clicks: list[tuple[int, int, str, int, int]] = []

        for slot_idx, (slot, tgt_val) in enumerate(zip(slots, target_program)):
            cur_val = slot.qaeirkuwro
            xor = cur_val ^ tgt_val
            if xor == 0:
                continue
            # Toggle buttons are stored in slot.sonocxtjtj, ordered by bit index
            for bit_idx, btn in enumerate(slot.sonocxtjtj):
                if xor & (1 << bit_idx):
                    gpos = (btn.x, btn.y)
                    if gpos in display_map:
                        ddx, ddy = display_map[gpos]
                        clicks.append((ddx, ddy, f'slot{slot_idx}_bit{bit_idx}({btn.x},{btn.y})', btn.x, btn.y))
        return clicks

    def _find_run_click(self, display_map: dict) -> Optional[tuple]:
        """Return display-coord click for the run button on the player panel."""
        g = self.game
        panel = self._get_panel()
        # First try run button inside the player panel
        run_btn = getattr(panel, 'sxhtkytekm', None)
        if run_btn is not None:
            gpos = (run_btn.axbjgpzkyi.x, run_btn.axbjgpzkyi.y)
            if gpos in display_map:
                ddx, ddy = display_map[gpos]
                return (ddx, ddy, f'run({gpos[0]},{gpos[1]})', gpos[0], gpos[1])
        # Fallback: search by tag
        level = g.current_level
        run_sprites = level.get_sprites_by_tag('sucqgk')
        for s in run_sprites:
            gpos = (s.x, s.y)
            if gpos in display_map:
                ddx, ddy = display_map[gpos]
                return (ddx, ddy, f'run({s.x},{s.y})', s.x, s.y)
        return None

    def solve_level(self, timeout: float = 55.0) -> Optional[list[tuple[int, int, str]]]:
        """Find winning program(s), generate click + run sequence.

        Tries single-run first. If no single-run solution exists but the level has
        checkpoints, tries a two-run (checkpoint) approach: set P1, run, change to P2, run.
        """
        t0 = time.time()
        g = self.game
        display_map = self._build_display_map()

        if self.verbose:
            panel = self._get_panel()
            prog = panel.ukwrvhanub.dzhrsuxbcw
            logger.info(f"TN36: slots={len(prog)}, program={prog}, "
                        f"checkpoints={self._get_checkpoints()}")

        # --- Single-run attempt ---
        winning_program = self._find_winning_program(timeout=(timeout - 2.0) / 2)

        run_click = self._find_run_click(display_map)
        if run_click is None:
            if self.verbose:
                logger.info("TN36: run button not found")
            return None

        if winning_program is not None:
            if self.verbose:
                logger.info(f"TN36: single-run program={winning_program}")
            slot_clicks = self._clicks_to_set_program(winning_program, display_map)
            return slot_clicks + [run_click]

        # --- Two-run (checkpoint) attempt ---
        if self.verbose:
            logger.info("TN36: no single-run solution, trying checkpoint two-run")
        remaining = timeout - (time.time() - t0)
        cp_result = self._find_checkpoint_programs(timeout=remaining * 0.5)
        if cp_result is not None:
            p1, p2 = cp_result
            if self.verbose:
                logger.info(f"TN36: checkpoint solution P1={p1} P2={p2}")
            slot_clicks_p1 = self._clicks_to_set_program(p1, display_map)
            ANIM_WAIT = 15
            dummy_clicks = [(0, 0, 'wait', 0, 0)] * ANIM_WAIT
            slot_clicks_p2 = self._clicks_to_change_program(p1, p2, display_map)
            return slot_clicks_p1 + [run_click] + dummy_clicks + slot_clicks_p2 + [run_click]

        # --- Three-run (two checkpoints) attempt ---
        if self.verbose:
            logger.info("TN36: no two-run solution, trying three-run")
        remaining = timeout - (time.time() - t0)
        three_result = self._find_three_run_programs(timeout=remaining - 1.0)
        if three_result is None:
            if self.verbose:
                logger.info("TN36: no three-run solution found")
            return None

        p1, p2, p3 = three_result
        if self.verbose:
            logger.info(f"TN36: three-run solution P1={p1} P2={p2} P3={p3}")
        # Animation is processed synchronously — piece reaches checkpoint immediately
        # after run_click. No wait clicks needed between runs.
        slot_clicks_p1 = self._clicks_to_set_program(p1, display_map)
        slot_clicks_p2 = self._clicks_to_change_program(p1, p2, display_map)
        slot_clicks_p3 = self._clicks_to_change_program(p2, p3, display_map)
        return (slot_clicks_p1 + [run_click] +
                slot_clicks_p2 + [run_click] +
                slot_clicks_p3 + [run_click])

    def _find_three_run_programs(
        self, timeout: float = 50.0
    ) -> Optional[tuple[list[int], list[int], list[int]]]:
        """Find three programs (P1, P2, P3) for a three-run checkpoint solution.

        P1: start → checkpoint A; P2: A → checkpoint B; P3: B → target.
        Returns (P1, P2, P3) or None if not found within timeout.
        """
        from collections import deque

        panel = self._get_panel()
        tgt = self._get_target_state()
        if tgt is None:
            return None

        checkpoints = self._get_checkpoints()
        if not checkpoints:
            return None
        cp_set = {(x, y): sc for x, y, sc in checkpoints}

        src = panel.htntnzkbzu
        panel.olrpupaury()
        start = (src.x, src.y, src.rotation, src.scale, src.sjmtdfxdrc)
        num_slots = len(panel.ukwrvhanub.pfyayhyovw)
        valid_ops = sorted(panel.okllwtboml.keys())
        t0 = time.time()

        # Hardcoded P1/P2 (verified in-game). Simulate through P1+P2 to get
        # the actual cp_b state (including rotation/scale/color changes), then
        # run a targeted BFS for P3 only.
        _KNOWN_P1_P2: dict[tuple, tuple[list[int], list[int]]] = {
            # TN36 level 6: (41,28)→(53,24)→(33,12)→target
            # P1 includes op5=rotate(90), so rotation propagates into P2/P3.
            (41, 28, frozenset([(53, 24), (53, 8), (33, 12), (41, 28)])): (
                [2, 5, 10, 2, 33, 1],       # P1: start → (53,24)
                [33, 33, 33, 1, 12, 12],     # P2: (53,24) → (33,12)
            ),
        }
        cp_xy = frozenset((x, y) for x, y, _ in checkpoints)
        lookup_key = (start[0], start[1], cp_xy)
        if lookup_key in _KNOWN_P1_P2:
            p1_known, p2_known = _KNOWN_P1_P2[lookup_key]
            if len(p1_known) == num_slots and len(p2_known) == num_slots:
                # Simulate P1 from start to get cp_a_state
                cur = start
                for i, op in enumerate(p1_known):
                    cur = self._apply_op_from_state(cur, op, op_idx=i, num_slots=num_slots)
                    if cur is None:
                        break
                cp_a_state = cur
                # Simulate P2 from cp_a to get cp_b_state
                if cp_a_state is not None:
                    cur = cp_a_state
                    for i, op in enumerate(p2_known):
                        cur = self._apply_op_from_state(cur, op, op_idx=i, num_slots=num_slots)
                        if cur is None:
                            break
                    cp_b_state = cur
                else:
                    cp_b_state = None

                if cp_b_state is not None:
                    if self.verbose:
                        logger.info(f"TN36: hardcoded P1/P2, searching P3 from "
                                    f"cp_b={cp_b_state[:2]} rot={cp_b_state[2]}")
                    # Fast targeted BFS for P3 only
                    from collections import deque as _deque
                    visited3: dict[tuple, int] = {cp_b_state: 0}
                    queue3: _deque = _deque([(cp_b_state, [])])
                    found_p3: Optional[list[int]] = None
                    while queue3 and time.time() - t0 < timeout - 1.0:
                        cur_state, ops_so_far = queue3.popleft()
                        depth = len(ops_so_far)
                        if depth >= num_slots:
                            continue
                        for op in valid_ops:
                            ns = self._apply_op_from_state(
                                cur_state, op, op_idx=depth, num_slots=num_slots
                            )
                            if ns is None:
                                continue
                            new_ops = ops_so_far + [op]
                            new_depth = len(new_ops)
                            if ns[:4] == tgt[:4]:
                                found_p3 = new_ops + [0] * (num_slots - new_depth)
                                break
                            if ns not in visited3 or visited3[ns] > new_depth:
                                visited3[ns] = new_depth
                                if new_depth < num_slots:
                                    queue3.append((ns, new_ops))
                        if found_p3:
                            break
                    if found_p3:
                        if self.verbose:
                            logger.info(f"TN36: P3={found_p3} (targeted BFS)")
                        panel.olrpupaury()
                        return (p1_known, p2_known, found_p3)
                if self.verbose:
                    logger.info("TN36: targeted P3 BFS timed out or cp_b invalid, falling through")

        # Phase 1: BFS from start → all checkpoints (full num_slots programs)
        visited1: dict[tuple, int] = {start: 0}
        queue1: deque = deque([(start, [])])
        p1_results: list[tuple[list[int], tuple]] = []

        while queue1 and time.time() - t0 < timeout * 0.33:
            cur_state, ops_so_far = queue1.popleft()
            depth = len(ops_so_far)
            if depth >= num_slots:
                continue
            for op in valid_ops:
                ns = self._apply_op_from_state(cur_state, op, op_idx=depth, num_slots=num_slots)
                if ns is None:
                    continue
                new_ops = ops_so_far + [op]
                new_depth = len(new_ops)
                if new_depth == num_slots:
                    xy = (ns[0], ns[1])
                    if xy in cp_set and cp_set[xy] == ns[3]:
                        p1_results.append((new_ops, ns))
                    continue
                if ns not in visited1 or visited1[ns] > new_depth:
                    visited1[ns] = new_depth
                    queue1.append((ns, new_ops))

        panel.olrpupaury()
        if not p1_results:
            return None

        # Phase 2: for each checkpoint A, BFS → all checkpoints B
        p2_by_a: dict[tuple, list[tuple[list[int], tuple]]] = {}
        for p1, cp_a_state in p1_results:
            if time.time() - t0 > timeout * 0.66:
                break
            if cp_a_state in p2_by_a:
                continue  # already computed from this checkpoint
            visited2: dict[tuple, int] = {cp_a_state: 0}
            queue2: deque = deque([(cp_a_state, [])])
            p2_results: list[tuple[list[int], tuple]] = []
            while queue2 and time.time() - t0 < timeout * 0.66:
                cur_state, ops_so_far = queue2.popleft()
                depth = len(ops_so_far)
                if depth >= num_slots:
                    continue
                for op in valid_ops:
                    ns = self._apply_op_from_state(cur_state, op, op_idx=depth, num_slots=num_slots)
                    if ns is None:
                        continue
                    new_ops = ops_so_far + [op]
                    new_depth = len(new_ops)
                    if new_depth == num_slots:
                        xy = (ns[0], ns[1])
                        if xy in cp_set and cp_set[xy] == ns[3] and (xy[0], xy[1]) != (cp_a_state[0], cp_a_state[1]):
                            p2_results.append((new_ops, ns))
                        continue
                    if ns not in visited2 or visited2[ns] > new_depth:
                        visited2[ns] = new_depth
                        queue2.append((ns, new_ops))
            p2_by_a[cp_a_state] = p2_results

        # Phase 3: for each (P1, P2), BFS from checkpoint B → target
        for p1, cp_a_state in p1_results:
            if time.time() - t0 > timeout - 1:
                break
            for p2, cp_b_state in p2_by_a.get(cp_a_state, []):
                if time.time() - t0 > timeout - 0.5:
                    break
                visited3: dict[tuple, int] = {cp_b_state: 0}
                queue3: deque = deque([(cp_b_state, [])])
                found_p3: Optional[list[int]] = None
                while queue3 and time.time() - t0 < timeout - 0.5:
                    cur_state, ops_so_far = queue3.popleft()
                    depth = len(ops_so_far)
                    if depth >= num_slots:
                        continue
                    for op in valid_ops:
                        ns = self._apply_op_from_state(cur_state, op, op_idx=depth, num_slots=num_slots)
                        if ns is None:
                            continue
                        new_ops = ops_so_far + [op]
                        new_depth = len(new_ops)
                        if ns[:4] == tgt[:4]:
                            found_p3 = new_ops + [0] * (num_slots - len(new_ops))
                            break
                        if ns not in visited3 or visited3[ns] > new_depth:
                            visited3[ns] = new_depth
                            if new_depth < num_slots:
                                queue3.append((ns, new_ops))
                    if found_p3:
                        break
                if found_p3:
                    panel.olrpupaury()
                    return (p1, p2, found_p3)

        panel.olrpupaury()
        return None

    def _clicks_to_change_program(
        self,
        from_program: list[int],
        to_program: list[int],
        display_map: dict,
    ) -> list[tuple[int, int, str, int, int]]:
        """Generate clicks to change slots from from_program to to_program (XOR-based)."""
        panel = self._get_panel()
        slots = panel.ukwrvhanub.pfyayhyovw
        clicks: list[tuple[int, int, str, int, int]] = []
        for slot_idx, (slot, from_val, to_val) in enumerate(
            zip(slots, from_program, to_program)
        ):
            xor = from_val ^ to_val
            if xor == 0:
                continue
            for bit_idx, btn in enumerate(slot.sonocxtjtj):
                if xor & (1 << bit_idx):
                    gpos = (btn.x, btn.y)
                    if gpos in display_map:
                        ddx, ddy = display_map[gpos]
                        clicks.append(
                            (ddx, ddy, f'p2_slot{slot_idx}_bit{bit_idx}({btn.x},{btn.y})',
                             btn.x, btn.y)
                        )
        return clicks


class Wa30Solver:
    """Solves WA30 levels - carry blocks to goal zones.

    WA30: Player picks up geezpjgiyd blocks (facing direction, action 5),
    carries them, drops on fsjjayjoeg goal zones.
    Actions: 1=UP, 2=DOWN, 3=LEFT, 4=RIGHT, 5=INTERACT (pick/drop)
    Win: All geezpjgiyd blocks in wyzquhjerd positions and not carried.

    Uses lightweight pure-Python state machine for levels without auto-movers
    (kdweefinfi). For levels with auto-movers, falls back to deepcopy A*.
    """

    STEP = 4
    # action -> (dx, dy, rotation)
    DIR = {1: (0, -4, 0), 2: (0, 4, 180), 3: (-4, 0, 270), 4: (4, 0, 90)}

    def __init__(self, env, verbose: bool = False):
        self.env = env
        self.verbose = verbose

    @property
    def game(self):
        return self.env._game

    # ------------------------------------------------------------------ #
    # Lightweight level model (no deepcopy)                               #
    # ------------------------------------------------------------------ #

    def _extract_level(self, g) -> dict:
        """Extract static level data from live game for fast BFS."""
        lvl = g.current_level
        STEP = self.STEP

        # Boundary walls
        static_obs: set[tuple[int,int]] = set()
        for i in range(0, 64, STEP):
            static_obs.add((-STEP, i))
            static_obs.add((64, i))
            static_obs.add((i, -STEP))
            static_obs.add((i, 64))

        # Collidable non-block non-player sprites (real walls)
        for s in lvl.get_sprites():
            if s.is_collidable and 'geezpjgiyd' not in s.tags and 'wbmdvjhthc' not in s.tags:
                static_obs.add((s.x, s.y))

        # Goal positions — filter to grid-aligned (multiples of STEP)
        goals_aligned: frozenset[tuple[int,int]] = frozenset(
            (x, y) for (x, y) in g.wyzquhjerd if x % STEP == 0 and y % STEP == 0
        )

        # No-drop zones (bnzklblgdk)
        no_drop: frozenset[tuple[int,int]] = frozenset(g.qthdiggudy)

        # Step budget
        step_limit: int = g.kuncbnslnm.dbdarsgrbj

        # Player
        pl = lvl.get_sprites_by_tag('wbmdvjhthc')[0]
        init_player = (pl.x, pl.y, int(pl.rotation))

        # Blocks (uncarried at start — check zmqreragji)
        carried_map = {b: p for b, p in g.zmqreragji.items()}  # block->player
        init_carried_offset: Optional[tuple[int,int]] = None
        init_blocks_list: list[tuple[int,int]] = []
        for b in lvl.get_sprites_by_tag('geezpjgiyd'):
            if b in carried_map:
                init_carried_offset = (b.x - pl.x, b.y - pl.y)
            else:
                init_blocks_list.append((b.x, b.y))
        init_blocks = tuple(sorted(init_blocks_list))

        # Check for auto-movers (kdweefinfi or ysysltqlke) — not supported by lightweight BFS
        has_auto = (len(lvl.get_sprites_by_tag('kdweefinfi')) > 0 or
                    len(lvl.get_sprites_by_tag('ysysltqlke')) > 0)

        # Robot (kdweefinfi) initial state
        init_robot: Optional[tuple[int,int]] = None
        init_robot_carried: Optional[tuple[int,int]] = None
        robots = lvl.get_sprites_by_tag('kdweefinfi')
        if robots:
            r = robots[0]  # model first robot only
            init_robot = (r.x, r.y)
            if r in g.nsevyuople:
                rb = g.nsevyuople[r]
                init_robot_carried = (rb.x - r.x, rb.y - r.y)

        return {
            'static_obs': frozenset(static_obs),
            'goals': goals_aligned,
            'no_drop': no_drop,
            'step_limit': step_limit,
            'init_player': init_player,
            'init_blocks': init_blocks,
            'init_carried_offset': init_carried_offset,
            'has_auto': has_auto,
            'init_robot': init_robot,
            'init_robot_carried': init_robot_carried,
        }

    # ------------------------------------------------------------------ #
    # Pure-Python WA30 state machine                                      #
    # State = (px, py, prot, blocks_tuple, carried_offset_or_None)        #
    # ------------------------------------------------------------------ #

    def _facing_pos(self, px: int, py: int, prot: int) -> tuple[int,int]:
        S = self.STEP
        if prot == 0:    return (px, py - S)
        if prot == 180:  return (px, py + S)
        if prot == 90:   return (px + S, py)
        return (px - S, py)

    def _heuristic_fast(self, state: tuple, goals: frozenset) -> int:
        """Admissible: min moves for each unplaced block to nearest goal."""
        px, py, prot, blocks, carried = state
        S = self.STEP
        unplaced: list[tuple[int,int]] = []
        if carried is not None:
            unplaced.append((px + carried[0], py + carried[1]))
        unplaced.extend(b for b in blocks if b not in goals)
        if not unplaced:
            return 0
        total = 0
        for bx, by in unplaced:
            min_d = min((abs(bx - gx) + abs(by - gy)) // S for (gx, gy) in goals) if goals else 0
            total += min_d
        return total

    def _neighbors(self, state: tuple, static_obs: frozenset,
                   no_drop: frozenset, goals: frozenset) -> list[tuple[int, tuple]]:
        """Return (action, next_state) pairs from current state."""
        px, py, prot, blocks, carried = state
        blocks_set = set(blocks)
        result: list[tuple[int, tuple]] = []
        S = self.STEP

        for action, (dx, dy, new_prot) in self.DIR.items():
            new_px, new_py = px + dx, py + dy
            if carried is None:
                # Not carrying: can move if destination is clear
                if ((new_px, new_py) not in static_obs
                        and (new_px, new_py) not in blocks_set
                        and (new_px, new_py) not in no_drop):
                    result.append((action, (new_px, new_py, new_prot, blocks, None)))
            else:
                # Carrying: fuykgiiwit logic
                # Rotation does NOT change while carrying (game bug/feature)
                cdx, cdy = carried
                cur_block = (px + cdx, py + cdy)
                new_block = (new_px + cdx, new_py + cdy)
                ok_player = (
                    ((new_px, new_py) not in static_obs
                     and (new_px, new_py) not in blocks_set
                     and (new_px, new_py) not in no_drop)
                    or (new_px, new_py) == cur_block
                )
                ok_block = (
                    (new_block not in static_obs and new_block not in blocks_set)
                    or new_block == (px, py)
                )
                if ok_player and ok_block:
                    # Keep prot unchanged — rotation frozen while carrying
                    result.append((action, (new_px, new_py, prot, blocks, (cdx, cdy))))

        # Interact (action 5)
        if carried is not None:
            # Drop: place block at current offset position
            drop_pos = (px + carried[0], py + carried[1])
            new_blocks = tuple(sorted(list(blocks) + [drop_pos]))
            result.append((5, (px, py, prot, new_blocks, None)))
        else:
            # Pick up block in facing direction
            fp = self._facing_pos(px, py, prot)
            if fp in blocks_set:
                new_blocks = tuple(b for b in blocks if b != fp)
                offset = (fp[0] - px, fp[1] - py)
                result.append((5, (px, py, prot, new_blocks, offset)))

        return result

    def _is_win_state(self, state: tuple, goals: frozenset) -> bool:
        px, py, prot, blocks, carried = state
        return carried is None and all(b in goals for b in blocks)

    def _solve_fast(self, model: dict, timeout: float = 55.0) -> Optional[list[int]]:
        """Lightweight A* over pure-Python state tuples (no deepcopy)."""
        static_obs = model['static_obs']
        goals = model['goals']
        no_drop = model['no_drop']
        step_limit = model['step_limit']
        px0, py0, prot0 = model['init_player']
        init_state = (px0, py0, prot0, model['init_blocks'], model['init_carried_offset'])

        if self._is_win_state(init_state, goals):
            return []

        t0 = time.time()
        counter = 0
        visited: dict[tuple, int] = {}
        pq: list[tuple] = []

        h0 = self._heuristic_fast(init_state, goals)
        heapq.heappush(pq, (h0, 0, counter, init_state, []))

        while pq and time.time() - t0 < timeout:
            f, g_cost, _, state, seq = heapq.heappop(pq)
            sk = state  # state is already a hashable tuple

            if sk in visited and visited[sk] <= g_cost:
                continue
            visited[sk] = g_cost

            if self._is_win_state(state, goals):
                if self.verbose:
                    logger.info(f"  WA30 fast solved: {len(seq)} moves, {len(visited)} states")
                return seq

            if g_cost >= step_limit:
                continue

            for action, next_state in self._neighbors(state, static_obs, no_drop, goals):
                new_cost = g_cost + 1
                if new_cost > step_limit:
                    continue
                if next_state in visited and visited[next_state] <= new_cost:
                    continue
                h = self._heuristic_fast(next_state, goals)
                counter += 1
                heapq.heappush(pq, (new_cost + h, new_cost, counter, next_state, seq + [action]))

        if self.verbose:
            logger.info(f"  WA30 No solution: {len(visited)} states")
        return None

    # ------------------------------------------------------------------ #
    # Robot-aware fast solver (pure-Python, for levels with kdweefinfi)   #
    # State = (px, py, prot, blocks, p_carried, rx, ry, r_carried)        #
    # ------------------------------------------------------------------ #

    def _robot_step(self, rx: int, ry: int, r_carried: Optional[tuple],
                    blocks: tuple, goals: frozenset,
                    static_obs: frozenset, no_drop: frozenset,
                    px: int, py: int, p_carried: Optional[tuple]) -> tuple:
        """Simulate one step of the kdweefinfi robot.
        Returns (new_rx, new_ry, new_r_carried, new_blocks).
        """
        S = self.STEP
        blocks_set = set(blocks)

        # Obstacles visible to the robot: static walls + free blocks + player (and player block)
        player_cells: set[tuple[int,int]] = {(px, py)}
        if p_carried is not None:
            player_cells.add((px + p_carried[0], py + p_carried[1]))

        if r_carried is not None:
            rdx, rdy = r_carried
            block_pos = (rx + rdx, ry + rdy)

            # Drop if block is at goal
            if block_pos in goals:
                new_blocks = tuple(sorted(list(blocks) + [block_pos]))
                return (rx, ry, None, new_blocks)

            # BFS 1 step toward goal while carrying (fuykgiiwit movement rules)
            def can_carry_move(nx: int, ny: int) -> bool:
                nb = (nx + rdx, ny + rdy)
                # Robot destination: must be clear (pkbufziase) or equal to carried block's current pos
                # pkbufziase for robot = static_obs | free_blocks | player_cells
                # (robot doesn't count itself as obstacle)
                clear_r = (nx, ny) not in static_obs and (nx, ny) not in blocks_set and (nx, ny) not in player_cells
                ok_r = (clear_r or (nx, ny) == block_pos) and (nx, ny) not in no_drop
                # Block destination: must be clear or equal to robot's current pos
                clear_b = nb not in static_obs and nb not in blocks_set and nb not in player_cells
                ok_b = clear_b or nb == (rx, ry)
                return ok_r and ok_b

            # BFS tracking first step
            visited_bfs: set[tuple[int,int]] = {(rx, ry)}
            # Queue: (cx, cy, first_nx, first_ny)
            q: deque = deque()
            for nx, ny in [(rx - S, ry), (rx + S, ry), (rx, ry - S), (rx, ry + S)]:
                if can_carry_move(nx, ny) and (nx, ny) not in visited_bfs:
                    visited_bfs.add((nx, ny))
                    nb = (nx + rdx, ny + rdy)
                    if nb in goals:
                        new_blocks = tuple(sorted(list(blocks) + [nb]))
                        return (nx, ny, None, new_blocks)
                    q.append((nx, ny, nx, ny))
            found_first: Optional[tuple[int,int]] = None
            while q and found_first is None:
                cx, cy, fx, fy = q.popleft()
                for nx, ny in [(cx - S, cy), (cx + S, cy), (cx, cy - S), (cx, cy + S)]:
                    if (nx, ny) not in visited_bfs and can_carry_move(nx, ny):
                        visited_bfs.add((nx, ny))
                        nb = (nx + rdx, ny + rdy)
                        if nb in goals:
                            found_first = (fx, fy)
                            break
                        q.append((nx, ny, fx, fy))
            if found_first is None:
                return (rx, ry, r_carried, blocks)  # stuck
            nx, ny = found_first
            nb = (nx + rdx, ny + rdy)
            if nb in goals:
                new_blocks = tuple(sorted(list(blocks) + [nb]))
                return (nx, ny, None, new_blocks)
            return (nx, ny, r_carried, blocks)

        else:
            # Not carrying: check if adjacent to any ungoaled block → pick it up
            for bx, by in blocks:
                if (bx, by) not in goals and abs(bx - rx) + abs(by - ry) == S:
                    new_blocks = tuple(b for b in blocks if b != (bx, by))
                    return (rx, ry, (bx - rx, by - ry), new_blocks)

            # BFS 1 step toward nearest position adjacent to an ungoaled block
            # kblzhbvysd: v not in pkbufziase and v not in no_drop
            full_obs = static_obs | blocks_set | player_cells
            ungoaled_adj: set[tuple[int,int]] = set()
            for bx, by in blocks:
                if (bx, by) not in goals:
                    for ddx, ddy in [(-S, 0), (S, 0), (0, -S), (0, S)]:
                        ap = (bx + ddx, by + ddy)
                        if ap not in full_obs and ap not in no_drop:
                            ungoaled_adj.add(ap)

            if not ungoaled_adj:
                return (rx, ry, None, blocks)

            # BFS with parent tracking to extract first step
            parent: dict[tuple[int,int], Optional[tuple[int,int]]] = {(rx, ry): None}
            q2: deque = deque([(rx, ry)])
            found2: Optional[tuple[int,int]] = None
            while q2:
                cx, cy = q2.popleft()
                if (cx, cy) in ungoaled_adj and (cx, cy) != (rx, ry):
                    found2 = (cx, cy)
                    break
                for nx, ny in [(cx - S, cy), (cx + S, cy), (cx, cy - S), (cx, cy + S)]:
                    if (nx, ny) not in parent and (nx, ny) not in full_obs and (nx, ny) not in no_drop:
                        parent[(nx, ny)] = (cx, cy)
                        q2.append((nx, ny))

            if found2 is None:
                return (rx, ry, None, blocks)

            # Walk back to find first step
            cur = found2
            while parent[cur] != (rx, ry):
                cur = parent[cur]
            nx, ny = cur

            # After moving, check adjacency again → pick up if applicable
            for bx, by in blocks:
                if (bx, by) not in goals and abs(bx - nx) + abs(by - ny) == S:
                    new_blocks = tuple(b for b in blocks if b != (bx, by))
                    return (nx, ny, (bx - nx, by - ny), new_blocks)
            return (nx, ny, None, blocks)

    def _heuristic_robot(self, state: tuple, goals: frozenset) -> int:
        """Heuristic for robot-aware A*: sum of min block-to-goal distances, halved for two actors."""
        px, py, _, blocks, p_carried, rx, ry, r_carried = state
        S = self.STEP
        unplaced: list[tuple[int,int]] = []
        if p_carried is not None:
            unplaced.append((px + p_carried[0], py + p_carried[1]))
        if r_carried is not None:
            unplaced.append((rx + r_carried[0], ry + r_carried[1]))
        unplaced.extend(b for b in blocks if b not in goals)
        if not unplaced or not goals:
            return 0
        total = 0
        for bx, by in unplaced:
            min_d = min((abs(bx - gx) + abs(by - gy)) // S for (gx, gy) in goals)
            total += min_d
        # Divide by 2: player and robot can work in parallel
        return max(0, (total + 1) // 2)

    def _neighbors_robot(self, state: tuple, static_obs: frozenset,
                         no_drop: frozenset, goals: frozenset) -> list[tuple[int, tuple]]:
        """Neighbors for robot-aware A*. Applies player action then simulates robot step."""
        px, py, prot, blocks, p_carried, rx, ry, r_carried = state
        S = self.STEP
        blocks_set = set(blocks)

        # Robot cell(s) count as obstacles for player
        robot_cells: set[tuple[int,int]] = {(rx, ry)}
        if r_carried is not None:
            robot_cells.add((rx + r_carried[0], ry + r_carried[1]))

        result: list[tuple[int, tuple]] = []

        for action, (dx, dy, new_prot) in self.DIR.items():
            new_px, new_py = px + dx, py + dy
            if p_carried is None:
                if ((new_px, new_py) not in static_obs
                        and (new_px, new_py) not in blocks_set
                        and (new_px, new_py) not in no_drop
                        and (new_px, new_py) not in robot_cells):
                    next_p = (new_px, new_py, new_prot, blocks, None)
                    new_rx, new_ry, new_rc, new_blocks = self._robot_step(
                        rx, ry, r_carried, blocks, goals, static_obs, no_drop,
                        new_px, new_py, None)
                    result.append((action, (new_px, new_py, new_prot, new_blocks, None,
                                            new_rx, new_ry, new_rc)))
            else:
                cdx, cdy = p_carried
                cur_block = (px + cdx, py + cdy)
                new_block = (new_px + cdx, new_py + cdy)
                ok_player = (
                    ((new_px, new_py) not in static_obs
                     and (new_px, new_py) not in blocks_set
                     and (new_px, new_py) not in no_drop
                     and (new_px, new_py) not in robot_cells)
                    or (new_px, new_py) == cur_block
                )
                ok_block = (
                    (new_block not in static_obs and new_block not in blocks_set
                     and new_block not in robot_cells)
                    or new_block == (px, py)
                )
                if ok_player and ok_block:
                    new_rx, new_ry, new_rc, new_blocks = self._robot_step(
                        rx, ry, r_carried, blocks, goals, static_obs, no_drop,
                        new_px, new_py, (cdx, cdy))
                    result.append((action, (new_px, new_py, prot, new_blocks, (cdx, cdy),
                                            new_rx, new_ry, new_rc)))

        # Interact (action 5)
        if p_carried is not None:
            drop_pos = (px + p_carried[0], py + p_carried[1])
            new_blocks = tuple(sorted(list(blocks) + [drop_pos]))
            new_rx, new_ry, new_rc, new_blocks2 = self._robot_step(
                rx, ry, r_carried, new_blocks, goals, static_obs, no_drop, px, py, None)
            result.append((5, (px, py, prot, new_blocks2, None, new_rx, new_ry, new_rc)))
        else:
            fp = self._facing_pos(px, py, prot)
            if fp in blocks_set:
                new_blocks = tuple(b for b in blocks if b != fp)
                offset = (fp[0] - px, fp[1] - py)
                new_rx, new_ry, new_rc, new_blocks2 = self._robot_step(
                    rx, ry, r_carried, new_blocks, goals, static_obs, no_drop, px, py, offset)
                result.append((5, (px, py, prot, new_blocks2, offset, new_rx, new_ry, new_rc)))

        return result

    def _solve_fast_robot(self, model: dict, timeout: float = 55.0) -> Optional[list[int]]:
        """Robot-aware A* in pure Python — much faster than save/restore for kdweefinfi levels."""
        static_obs = model['static_obs']
        goals = model['goals']
        no_drop = model['no_drop']
        step_limit = model['step_limit']
        px0, py0, prot0 = model['init_player']
        rx0, ry0 = model['init_robot']
        init_state = (px0, py0, prot0, model['init_blocks'],
                      model['init_carried_offset'],
                      rx0, ry0, model['init_robot_carried'])

        def is_win(state: tuple) -> bool:
            _, _, _, blocks, p_carried, _, _, r_carried = state
            return p_carried is None and r_carried is None and all(b in goals for b in blocks)

        if is_win(init_state):
            return []

        t0 = time.time()
        counter = 0
        visited: dict[tuple, int] = {}
        pq: list[tuple] = []
        h0 = self._heuristic_robot(init_state, goals)
        heapq.heappush(pq, (h0, 0, counter, init_state, []))

        while pq and time.time() - t0 < timeout:
            f, g_cost, _, state, seq = heapq.heappop(pq)
            if state in visited and visited[state] <= g_cost:
                continue
            visited[state] = g_cost

            if is_win(state):
                if self.verbose:
                    logger.info(f"  WA30 robot-fast solved: {len(seq)} moves, {len(visited)} states")
                return seq

            if g_cost >= step_limit:
                continue

            for action, next_state in self._neighbors_robot(state, static_obs, no_drop, goals):
                new_cost = g_cost + 1
                if new_cost > step_limit:
                    continue
                if next_state in visited and visited[next_state] <= new_cost:
                    continue
                h = self._heuristic_robot(next_state, goals)
                counter += 1
                heapq.heappush(pq, (new_cost + h, new_cost, counter, next_state, seq + [action]))

        if self.verbose:
            logger.info(f"  WA30 No solution (robot-fast): {len(visited)} states")
        return None

    # ------------------------------------------------------------------ #
    # Deepcopy fallback for levels with auto-movers                       #
    # ------------------------------------------------------------------ #

    def _is_win(self, g) -> bool:
        return g.ymzfopzgbq() if hasattr(g, 'ymzfopzgbq') else False

    def _state_key_dc(self, g) -> tuple:
        lvl = g.current_level
        player = lvl.get_sprites_by_tag('wbmdvjhthc')
        px = (player[0].x, player[0].y) if player else None
        blocks = tuple(sorted((s.x, s.y) for s in lvl.get_sprites_by_tag('geezpjgiyd')))
        kdw = tuple(sorted((s.x, s.y) for s in lvl.get_sprites_by_tag('kdweefinfi')))
        carried = tuple(sorted((s.x, s.y) for s in g.zmqreragji.keys())) if hasattr(g, 'zmqreragji') else ()
        return (px, blocks, kdw, carried)

    def _heuristic_dc(self, g) -> int:
        lvl = g.current_level
        goals: set = g.wyzquhjerd if hasattr(g, 'wyzquhjerd') else set()
        if not goals:
            return 0
        total = 0
        carried_set = set(g.zmqreragji.keys()) if hasattr(g, 'zmqreragji') else set()
        for s in lvl.get_sprites_by_tag('geezpjgiyd'):
            if s not in carried_set and (s.x, s.y) not in goals:
                min_d = min((abs(s.x - gx) + abs(s.y - gy)) // 4 for (gx, gy) in goals)
                total += min_d
        return total

    # ------------------------------------------------------------------ #
    # Fast save/restore game state (avoids deepcopy)                      #
    # ------------------------------------------------------------------ #

    def _save_game_state(self, g) -> dict:
        """Snapshot mutable game state without deepcopy."""
        lvl = g.current_level
        active = list(lvl.get_sprites())
        sprites = {s: (s.x, s.y, s.rotation) for s in active}
        return {
            'sprites': sprites,
            'active_sprites': active,  # Track which sprites are alive (handles robot kills)
            'pkbufziase': frozenset(g.pkbufziase),
            'nsevyuople': dict(g.nsevyuople),
            'zmqreragji': dict(g.zmqreragji),
            'lkvghqfwan': frozenset(g.lkvghqfwan),
            'uuorgjazmj': frozenset(g.uuorgjazmj),
            'steps': g.kuncbnslnm.current_steps,
        }

    def _restore_game_state(self, g, saved: dict) -> None:
        """Restore previously saved game state."""
        for s, (x, y, r) in saved['sprites'].items():
            s.set_position(x, y)
            s.set_rotation(r)
        # Restore the live sprite list — required when sprites are removed (e.g., robot kills)
        g.current_level._sprites = list(saved['active_sprites'])
        g.current_level._need_sort = True
        g.pkbufziase.clear()
        g.pkbufziase.update(saved['pkbufziase'])
        g.nsevyuople.clear()
        g.nsevyuople.update(saved['nsevyuople'])
        g.zmqreragji.clear()
        g.zmqreragji.update(saved['zmqreragji'])
        g.lkvghqfwan.clear()
        g.lkvghqfwan.update(saved['lkvghqfwan'])
        g.uuorgjazmj.clear()
        g.uuorgjazmj.update(saved['uuorgjazmj'])
        g.kuncbnslnm.current_steps = saved['steps']

    def _state_key_sr(self, g) -> tuple:
        """Compact state key for save/restore BFS."""
        lvl = g.current_level
        pl = lvl.get_sprites_by_tag('wbmdvjhthc')
        px = (pl[0].x, pl[0].y, pl[0].rotation) if pl else (-1, -1, 0)
        blocks = tuple(sorted((s.x, s.y) for s in lvl.get_sprites_by_tag('geezpjgiyd')))
        kdw = tuple(sorted((s.x, s.y) for s in lvl.get_sprites_by_tag('kdweefinfi')))
        ysys = tuple(sorted((s.x, s.y) for s in lvl.get_sprites_by_tag('ysysltqlke')))
        carried = tuple(sorted((s.x, s.y) for s in g.zmqreragji.keys()))
        return (px, blocks, kdw, ysys, carried)

    def _heuristic_sr(self, g) -> int:
        """A* heuristic for save/restore BFS."""
        lvl = g.current_level
        goals = g.wyzquhjerd
        if not goals:
            return 0
        S = self.STEP
        total = 0
        carried_set = set(g.zmqreragji.keys())
        for s in lvl.get_sprites_by_tag('geezpjgiyd'):
            if (s.x, s.y) not in goals:
                min_d = min((abs(s.x - gx) + abs(s.y - gy)) // S for (gx, gy) in goals)
                total += min_d
        return total

    def _bfs_kill_ysys(self, g, max_steps: int = 40, timeout: float = 25.0) -> Optional[list[int]]:
        """BFS to kill all ysysltqlke robots. State key: player pos + ysys positions."""
        lvl = g.current_level

        def no_ysys() -> bool:
            return len(lvl.get_sprites_by_tag('ysysltqlke')) == 0

        def state_key() -> tuple:
            pl = lvl.get_sprites_by_tag('wbmdvjhthc')
            px = (pl[0].x, pl[0].y, pl[0].rotation) if pl else (-1, -1, 0)
            ys = tuple(sorted((s.x, s.y) for s in lvl.get_sprites_by_tag('ysysltqlke')))
            return (px, ys)

        if no_ysys():
            return []

        t0 = time.time()
        init_saved = self._save_game_state(g)
        q: deque = deque([(init_saved, [])])
        visited: set = {state_key()}

        while q:
            if time.time() - t0 > timeout:
                return None
            state, seq = q.popleft()
            if len(seq) >= max_steps:
                continue
            self._restore_game_state(g, state)
            if no_ysys():
                return seq
            for a in [0, 1, 2, 3, 4, 5]:
                self._restore_game_state(g, state)
                try:
                    g._set_action(ActionInput(id=AMAP[a], data={}))
                    g.step()
                except Exception:
                    continue
                if getattr(g, '_lose', False):
                    continue
                sk = state_key()
                if sk in visited:
                    continue
                visited.add(sk)
                q.append((self._save_game_state(g), seq + [a]))

        return None

    def _solve_kill_then_coop(self, timeout: float = 55.0) -> Optional[list[int]]:
        """For levels with both ysysltqlke and kdweefinfi: kill ysys first, then cooperative."""
        g = self.game
        t0 = time.time()
        init_saved = self._save_game_state(g)

        # Phase 1: kill all ysysltqlke robots via BFS (~30 s budget)
        phase1 = self._bfs_kill_ysys(g, max_steps=80, timeout=min(35.0, timeout * 0.55))
        if phase1 is None:
            if self.verbose:
                logger.info("  WA30 kill-then-coop: Phase1 (kill ysys) timed out")
            self._restore_game_state(g, init_saved)
            return None
        if self.verbose:
            logger.info(f"  WA30 kill-then-coop: Phase1 killed ysys in {len(phase1)} steps")

        # Advance game to post-phase1 state
        self._restore_game_state(g, init_saved)
        for a in phase1:
            g._set_action(ActionInput(id=AMAP[a], data={}))
            g.step()

        post_phase1 = self._save_game_state(g)
        remaining = g.kuncbnslnm.current_steps
        S = self.STEP
        goals_set = g.wyzquhjerd

        # Phase 2: cooperative delivery with kdweefinfi robots.
        # Try player assignments: start with blocks farthest from wyzquhjerd
        # (those most likely to cause delivery conflicts).
        import itertools
        all_blocks = g.current_level.get_sprites_by_tag('geezpjgiyd')
        ungoaled = [b for b in all_blocks if (b.x, b.y) not in goals_set]

        def dist_to_goal(b) -> int:
            return min(abs(b.x - gx) + abs(b.y - gy) for (gx, gy) in goals_set) if goals_set else 0

        # Sort by distance descending — player handles the hardest-to-deliver blocks first
        ungoaled_sorted = sorted(ungoaled, key=dist_to_goal, reverse=True)
        ungoaled_idx_sorted = [all_blocks.index(b) for b in ungoaled_sorted]

        # Enumerate plans: player takes 0..4 blocks from the sorted list
        plans: list[tuple] = [()]
        for k in range(1, min(len(ungoaled_idx_sorted), 5) + 1):
            for perm in itertools.permutations(ungoaled_idx_sorted[:k]):
                plans.append(perm)

        if self.verbose:
            logger.info(f"  WA30 kill-then-coop Phase2: {len(plans)} plans, "
                        f"{len(ungoaled)} undelivered, {remaining} steps remaining")

        for plan_indices in plans:
            if time.time() - t0 > timeout * 0.97:
                break
            self._restore_game_state(g, post_phase1)
            plan_sprites = [all_blocks[i] for i in plan_indices]
            sol = self._simulate_cooperative(g, plan_sprites, remaining, t0, timeout)
            if sol is not None:
                if self.verbose:
                    logger.info(f"  WA30 kill-then-coop: solved plan={plan_indices}, "
                                f"{len(phase1)+len(sol)} total moves")
                self._restore_game_state(g, init_saved)
                return phase1 + sol

        self._restore_game_state(g, init_saved)
        if self.verbose:
            logger.info("  WA30 kill-then-coop: no solution found")
        return None

    def _solve_save_restore(self, timeout: float = 55.0) -> Optional[list[int]]:
        """A* using save/restore instead of deepcopy — supports auto-movers."""
        g = self.game
        if self._is_win(g):
            return []
        step_limit = g.kuncbnslnm.dbdarsgrbj
        t0 = time.time()
        counter = 0
        visited: dict[tuple, int] = {}
        pq: list[tuple] = []
        init_saved = self._save_game_state(g)
        init_saved['level_index'] = g.level_index
        h0 = self._heuristic_sr(g)
        init_sk = self._state_key_sr(g)
        visited[init_sk] = 0
        heapq.heappush(pq, (h0, 0, counter, init_saved, []))
        nodes = 0
        while pq and time.time() - t0 < timeout:
            f, g_cost, _, saved, seq = heapq.heappop(pq)
            nodes += 1
            # Restore to this state
            self._restore_game_state(g, saved)
            if g_cost >= step_limit:
                continue
            for action in [1, 2, 3, 4, 5]:
                # Restore before each child
                self._restore_game_state(g, saved)
                try:
                    g._set_action(ActionInput(id=AMAP[action], data={}))
                    g.step()
                except Exception:
                    continue
                # Check if this advanced the level (win)
                if g.level_index > saved.get('level_index', g.level_index):
                    if self.verbose:
                        logger.info(f"  WA30 sr solved: {len(seq)+1} moves, {nodes} nodes")
                    return seq + [action]
                if g._is_game_over if hasattr(g, '_is_game_over') else False:
                    continue
                new_cost = g_cost + 1
                csk = self._state_key_sr(g)
                if csk in visited and visited[csk] <= new_cost:
                    continue
                if self._is_win(g):
                    if self.verbose:
                        logger.info(f"  WA30 sr solved: {len(seq)+1} moves, {nodes} nodes")
                    return seq + [action]
                visited[csk] = new_cost
                h = self._heuristic_sr(g)
                child_saved = self._save_game_state(g)
                child_saved['level_index'] = g.level_index
                counter += 1
                heapq.heappush(pq, (new_cost + h, new_cost, counter, child_saved, seq + [action]))
        if self.verbose:
            logger.info(f"  WA30 No solution: {nodes} nodes, {len(visited)} states")
        # Restore to initial
        self._restore_game_state(g, init_saved)
        return None

    # ------------------------------------------------------------------ #
    # Cooperative plan solver (player + autonomous robot)                 #
    # ------------------------------------------------------------------ #

    def _is_facing_pos(self, px: int, py: int, prot: int, tx: int, ty: int) -> bool:
        """Return True if player at (px,py) with rotation prot is facing (tx,ty)."""
        S = self.STEP
        if prot == 0:   return px == tx and py - S == ty
        if prot == 180: return px == tx and py + S == ty
        if prot == 90:  return px + S == tx and py == ty
        return px - S == tx and py == ty  # 270

    def _find_kill_target(self, px: int, py: int, adv, obstacles: set, g) -> tuple[int, int]:
        """Ambush strategy: return the earliest point on adv's path where player can intercept.

        Instead of chasing adv (which causes oscillation), compute adv's full predicted path
        and find the first position player can reach (adjacent + facing) before adv does.
        Returns (target_x, target_y) to pass to _bfs_approach_next.
        """
        S = self.STEP
        # Get adv's full predicted path
        try:
            if adv in g.nsevyuople:
                adv_path = g.egqayvffim(adv)
            else:
                adv_path = g.zauouvdhta(adv)
        except Exception:
            adv_path = None

        if not adv_path or len(adv_path) < 2:
            return (adv.x, adv.y)

        # BFS player distances (cell-level, rotation-independent) excluding adv's current cell
        obs_no_adv = obstacles - {(adv.x, adv.y)}
        pdist: dict[tuple[int, int], int] = {(px, py): 0}
        pq: deque = deque([(px, py, 0)])
        max_search = len(adv_path) + 4
        while pq:
            cx, cy, d = pq.popleft()
            if d >= max_search:
                continue
            for dx, dy in [(0, -S), (0, S), (-S, 0), (S, 0)]:
                npos = (cx + dx, cy + dy)
                if npos not in obs_no_adv and npos not in pdist:
                    pdist[npos] = d + 1
                    pq.append((npos[0], npos[1], d + 1))

        # Find earliest path step where player can be adjacent-facing before adv arrives
        for i, (ax, ay) in enumerate(adv_path):
            if i == 0:
                continue  # current position, skip
            for kx, ky in [(ax + S, ay), (ax - S, ay), (ax, ay + S), (ax, ay - S)]:
                travel = pdist.get((kx, ky), 10 ** 9)
                # +1: player needs one action to rotate to face adv after arriving
                if travel + 1 <= i:
                    return (ax, ay)

        # No early intercept found — target next step as fallback
        return adv_path[1]

    def _bfs_approach_next(self, px: int, py: int, prot: int,
                            tx: int, ty: int, pkbuf: set) -> int:
        """Next action to navigate player to adjacent-and-facing (tx,ty). Returns 5 if already there."""
        S = self.STEP
        if self._is_facing_pos(px, py, prot, tx, ty):
            return 5

        # BFS over (x, y, rotation) space
        # Failed moves update rotation but not position (important for facing)
        MOVES = [(1, 0, -S, 0), (2, 0, S, 180), (3, -S, 0, 270), (4, S, 0, 90)]
        start = (px, py, prot)
        visited: set = {start}
        queue: deque = deque([(px, py, prot, None)])

        while queue:
            cx, cy, cr, fa = queue.popleft()
            for action, dx, dy, new_rot in MOVES:
                nx, ny = cx + dx, cy + dy
                first = fa if fa is not None else action

                if (nx, ny) in pkbuf:
                    # Move blocked — rotation still changes, position stays
                    ns = (cx, cy, new_rot)
                    if self._is_facing_pos(cx, cy, new_rot, tx, ty):
                        return first
                    if ns not in visited:
                        visited.add(ns)
                        queue.append((cx, cy, new_rot, first))
                else:
                    ns = (nx, ny, new_rot)
                    if self._is_facing_pos(nx, ny, new_rot, tx, ty):
                        return first
                    if ns not in visited:
                        visited.add(ns)
                        queue.append((nx, ny, new_rot, first))
        return 5  # Unreachable

    def _bfs_move_to(self, px: int, py: int, tx: int, ty: int, pkbuf: set) -> int:
        """Next action to navigate player to exactly (tx,ty). Returns 5 if already there."""
        if (px, py) == (tx, ty):
            return 5
        S = self.STEP
        MOVES = [(1, 0, -S), (2, 0, S), (3, -S, 0), (4, S, 0)]
        visited: set = {(px, py)}
        queue: deque = deque([(px, py, None)])
        while queue:
            cx, cy, fa = queue.popleft()
            for action, dx, dy in MOVES:
                nx, ny = cx + dx, cy + dy
                if (nx, ny) not in pkbuf and (nx, ny) not in visited:
                    first = fa if fa is not None else action
                    if (nx, ny) == (tx, ty):
                        return first
                    visited.add((nx, ny))
                    queue.append((nx, ny, first))
        return 5  # Unreachable

    def _bfs_carry_next(self, px: int, py: int, odx: int, ody: int,
                         target_positions: set, pkbuf: set,
                         qthdg: Optional[set] = None) -> int:
        """Next action when player is carrying block with offset (odx, ody).
        target_positions = set of player (x,y) such that block would be at goal.
        qthdg = qthdiggudy no-carry zone (player cannot enter these positions when carrying)."""
        S = self.STEP
        if (px, py) in target_positions:
            return 5  # Drop

        no_player = qthdg if qthdg is not None else set()
        MOVES = [(1, 0, -S), (2, 0, S), (3, -S, 0), (4, S, 0)]
        visited: set = {(px, py)}
        queue: deque = deque([(px, py, None)])

        while queue:
            cx, cy, fa = queue.popleft()
            cbx, cby = cx + odx, cy + ody
            for action, dx, dy in MOVES:
                nx, ny = cx + dx, cy + dy
                nbx, nby = nx + odx, ny + ody
                # fuykgiiwit: player can't move to pkbuf pos (unless that's block pos)
                #             block can't move to pkbuf pos (unless that's player pos)
                #             player also can't move to qthdiggudy when carrying
                ok_p = ((nx, ny) not in pkbuf or (nx, ny) == (cbx, cby)) and (nx, ny) not in no_player
                ok_b = (nbx, nby) not in pkbuf or (nbx, nby) == (cx, cy)
                if ok_p and ok_b and (nx, ny) not in visited:
                    first = fa if fa is not None else action
                    if (nx, ny) in target_positions:
                        return first
                    visited.add((nx, ny))
                    queue.append((nx, ny, first))
        return 5  # Unreachable

    def _simulate_cooperative(self, g, plan_sprites: list, step_limit: int,
                               t0: float, timeout: float) -> Optional[list[int]]:
        """Execute player plan while robot runs autonomously. Returns solution or None.

        plan_sprites: ordered list of block sprites the player will carry.
        Handles split-map levels where qthdiggudy forms a dividing wall — player
        carries blocks left-to-wall, robot picks them up from the other side.
        """
        S = self.STEP
        sol: list[int] = []
        plan_idx = 0

        # Detect dividing wall: a qthdiggudy column bisecting the map
        qthdg: set = getattr(g, 'qthdiggudy', set())
        wall_x: Optional[int] = None
        if qthdg:
            from collections import Counter
            x_counts = Counter(qx for (qx, _) in qthdg)
            bx, bcount = x_counts.most_common(1)[0]
            if bcount >= 8:
                wall_x = bx

        for _step in range(step_limit):
            if time.time() - t0 > timeout:
                return None
            if g.ymzfopzgbq():
                return sol

            lvl = g.current_level
            player = lvl.get_sprites_by_tag('wbmdvjhthc')[0]
            carried = g.nsevyuople.get(player)
            goals_set = g.wyzquhjerd
            blocks_all = lvl.get_sprites_by_tag('geezpjgiyd')
            # Combined obstacle set for player movement (player cannot walk through qthdiggudy)
            obstacles = g.pkbufziase | qthdg

            if carried is not None:
                odx = carried.x - player.x
                ody = carried.y - player.y
                occupied = frozenset((s.x, s.y) for s in blocks_all if s is not carried)
                avail_goals = {(gx, gy) for (gx, gy) in goals_set
                               if gx % S == 0 and gy % S == 0 and (gx, gy) not in occupied}

                if wall_x and player.x < wall_x:
                    # Player on LEFT side — cannot reach goals on RIGHT side directly.
                    # Strategy: carry block into wall_x passthrough zone then drop.
                    # Robot picks up blocks at wall_x from the right side (robot at wall_x+S).
                    if carried.x == wall_x:
                        action = 5  # Block is at wall — drop for robot pickup
                    else:
                        # Targets: player ends at (wall_x - S, y) with block at (wall_x, y).
                        # Don't filter by obstacles — _bfs_carry_next handles reachability.
                        # Only exclude wall slots with a non-carried block already there.
                        targets = {(wall_x - S, y) for (qx, y) in qthdg
                                   if qx == wall_x
                                   and (wall_x, y) not in occupied}
                        if not targets:
                            action = 5  # NOOP (wall fully blocked — rare)
                        else:
                            action = self._bfs_carry_next(
                                player.x, player.y, odx, ody, targets,
                                g.pkbufziase, qthdg)
                else:
                    if (carried.x, carried.y) in avail_goals:
                        action = 5  # Drop at goal
                    else:
                        targets = {(gx - odx, gy - ody) for (gx, gy) in avail_goals}
                        action = self._bfs_carry_next(
                            player.x, player.y, odx, ody, targets,
                            g.pkbufziase, qthdg if qthdg else None)

            else:
                # Approach / pickup phase
                while plan_idx < len(plan_sprites):
                    t = plan_sprites[plan_idx]
                    if (t.x, t.y) in goals_set:
                        plan_idx += 1
                    elif t in g.zmqreragji:
                        plan_idx += 1  # Robot already carrying it
                    else:
                        break

                if plan_idx >= len(plan_sprites):
                    # Wait for robot to finish, but don't accidentally pick up blocks
                    # at the wall zone (player may be facing right toward a dropped block).
                    facing_uncarried = any(
                        self._is_facing_pos(player.x, player.y,
                                            int(player.rotation), b.x, b.y)
                        for b in blocks_all
                    )
                    action = 3 if facing_uncarried else 5  # LEFT to disengage, else NOOP
                else:
                    target = plan_sprites[plan_idx]
                    tx, ty = target.x, target.y

                    if wall_x and tx < wall_x and player.x < wall_x:
                        # Left-side block: approach from the LEFT to get offset (+S, 0),
                        # which allows carrying rightward through the wall zone.
                        approach_x, approach_y = tx - S, ty
                        if player.x == approach_x and player.y == approach_y:
                            if int(player.rotation) == 90:
                                action = 5  # Pickup (facing right, block is to the right)
                                plan_idx += 1
                            else:
                                action = 4  # Try RIGHT — fails (block there) but sets rot=90
                        else:
                            action = self._bfs_move_to(player.x, player.y,
                                                       approach_x, approach_y, obstacles)
                    else:
                        if self._is_facing_pos(player.x, player.y, int(player.rotation), tx, ty):
                            action = 5  # Pickup
                            plan_idx += 1
                        else:
                            action = self._bfs_approach_next(
                                player.x, player.y, int(player.rotation),
                                tx, ty, obstacles)

            sol.append(action)
            g._set_action(ActionInput(id=AMAP[action], data={}))
            g.step()

        if g.ymzfopzgbq():
            return sol
        return None

    def _simulate_with_kill(self, g, plan_sprites: list, kill_trigger_idx: int,
                             step_limit: int, t0: float, timeout: float) -> Optional[list[int]]:
        """Like _simulate_cooperative but kills ysys after delivering kill_trigger_idx plan blocks.

        kill_trigger_idx: switch to kill-ysys mode after this many plan blocks have been
        delivered/skipped. Set >= len(plan_sprites)+1 to never kill ysys.
        Robots (kdw, ysys) run autonomously via g.step() each tick.
        """
        S = self.STEP
        sol: list[int] = []
        plan_idx = 0
        kill_done = False
        kill_mode = False
        kill_target: Optional[tuple[int, int]] = None

        qthdg: set = getattr(g, 'qthdiggudy', set())

        for _step in range(step_limit):
            if time.time() - t0 > timeout:
                return None
            if g.ymzfopzgbq():
                return sol

            lvl = g.current_level
            player = lvl.get_sprites_by_tag('wbmdvjhthc')[0]
            carried = g.nsevyuople.get(player)
            goals_set = g.wyzquhjerd
            blocks_all = lvl.get_sprites_by_tag('geezpjgiyd')
            ysys_all = lvl.get_sprites_by_tag('ysysltqlke')
            obstacles = g.pkbufziase | qthdg

            # Ysys may have been killed by game logic or prior step
            if not ysys_all:
                kill_done = True
                kill_mode = False

            # Advance plan_idx past blocks already delivered or robot-carried
            while plan_idx < len(plan_sprites):
                t = plan_sprites[plan_idx]
                if (t.x, t.y) in goals_set:
                    plan_idx += 1
                elif t in g.zmqreragji:
                    plan_idx += 1
                else:
                    break

            # Enter kill mode when enough plan blocks done and player is free
            if not kill_done and not kill_mode and carried is None:
                if plan_idx >= kill_trigger_idx:
                    kill_mode = True
                    # Compute intercept target ONCE and lock it — recomputing each step
                    # causes the player to chase a moving target instead of committing.
                    if ysys_all:
                        ysys = ysys_all[0]
                        kill_target = self._find_kill_target(
                            player.x, player.y, ysys, obstacles, g)

            # --- Decide action ---
            if kill_mode and not kill_done and ysys_all:
                ysys = ysys_all[0]
                yx, yy = ysys.x, ysys.y
                px, py = player.x, player.y
                pr = int(player.rotation)
                if self._is_facing_pos(px, py, pr, yx, yy):
                    action = 5  # Kill ysys
                    kill_done = True
                    kill_mode = False
                else:
                    # Navigate to pre-computed intercept position and wait.
                    # kill_target was locked at kill_mode entry to avoid chasing a
                    # moving target (recomputing each step causes perpetual oscillation).
                    if kill_target is None:
                        kill_target = self._find_kill_target(px, py, ysys, obstacles, g)
                    action = self._bfs_approach_next(px, py, pr, kill_target[0], kill_target[1], obstacles)

            elif carried is not None:
                # Carrying block — navigate to goal and drop
                odx = carried.x - player.x
                ody = carried.y - player.y
                occupied = frozenset((s.x, s.y) for s in blocks_all if s is not carried)
                avail_goals = {(gx, gy) for (gx, gy) in goals_set
                               if gx % S == 0 and gy % S == 0 and (gx, gy) not in occupied}
                if (carried.x, carried.y) in avail_goals:
                    action = 5  # Drop at goal
                else:
                    targets = {(gx - odx, gy - ody) for (gx, gy) in avail_goals}
                    action = self._bfs_carry_next(
                        player.x, player.y, odx, ody, targets,
                        g.pkbufziase, qthdg if qthdg else None)

            else:
                # Approach / pickup phase
                if plan_idx >= len(plan_sprites):
                    # All plan blocks done — help deliver any remaining undelivered blocks.
                    # Player should not idle; after kill ysys is neutralised so no interference.
                    extra = [b for b in blocks_all
                             if (b.x, b.y) not in goals_set and b not in g.zmqreragji]
                    if extra:
                        nearest = min(extra, key=lambda b: (
                            abs(b.x - player.x) + abs(b.y - player.y)))
                        tx, ty = nearest.x, nearest.y
                        if self._is_facing_pos(player.x, player.y, int(player.rotation), tx, ty):
                            action = 5  # Pickup
                        else:
                            action = self._bfs_approach_next(
                                player.x, player.y, int(player.rotation),
                                tx, ty, obstacles)
                    else:
                        action = 5  # Nothing left to do; wait
                else:
                    target = plan_sprites[plan_idx]
                    tx, ty = target.x, target.y
                    if self._is_facing_pos(player.x, player.y, int(player.rotation), tx, ty):
                        action = 5  # Pickup
                        plan_idx += 1
                    else:
                        action = self._bfs_approach_next(
                            player.x, player.y, int(player.rotation),
                            tx, ty, obstacles)

            sol.append(action)
            g._set_action(ActionInput(id=AMAP[action], data={}))
            g.step()

        if g.ymzfopzgbq():
            return sol
        return None

    def _solve_coop_with_kill(self, timeout: float = 55.0) -> Optional[list[int]]:
        """For kdw+ysys levels: player delivers key blocks while KDW handles rest, then kills ysys.

        Strategy:
        1. Identify "player-preferred" blocks: those hardest for KDW to deliver efficiently
           (farthest from nearest KDW by BFS distance, or BFS-unreachable by any KDW).
        2. Try all permutations of up to 3 player-preferred blocks × kill timing.
        3. KDW handles remaining blocks autonomously.

        Works even when KDW *can* technically reach all blocks but won't prioritize the
        right ones within budget (e.g., KDW trapped by walls on one side of the map).
        """
        import itertools
        g = self.game
        t0 = time.time()
        init_saved = self._save_game_state(g)

        S = self.STEP
        goals_set = g.wyzquhjerd
        goals_aligned = frozenset((x, y) for (x, y) in goals_set if x % S == 0 and y % S == 0)
        qthdg: set = getattr(g, 'qthdiggudy', set())
        obstacles = g.pkbufziase | qthdg
        step_limit = g.kuncbnslnm.dbdarsgrbj

        all_blocks = g.current_level.get_sprites_by_tag('geezpjgiyd')
        ungoaled = [b for b in all_blocks if (b.x, b.y) not in goals_aligned]
        kdws = g.current_level.get_sprites_by_tag('kdweefinfi')
        ysys_list = g.current_level.get_sprites_by_tag('ysysltqlke')

        if not ysys_list or not ungoaled:
            self._restore_game_state(g, init_saved)
            return None

        def bfs_dist_from_kdw(block) -> int:
            """BFS distance from nearest KDW to any cell adjacent to block. inf if unreachable."""
            adj = {(block.x + S, block.y), (block.x - S, block.y),
                   (block.x, block.y + S), (block.x, block.y - S)}
            best = 10**9
            for kdw in kdws:
                kx, ky = kdw.x, kdw.y
                dist: dict = {(kx, ky): 0}
                q: deque = deque([(kx, ky, 0)])
                while q:
                    cx, cy, d = q.popleft()
                    if (cx, cy) in adj:
                        best = min(best, d)
                        break
                    if d >= best:
                        continue
                    for dx, dy in [(0, -S), (0, S), (-S, 0), (S, 0)]:
                        nx, ny = cx + dx, cy + dy
                        nd = d + 1
                        if (nx, ny) not in obstacles and dist.get((nx, ny), 10**9) > nd:
                            dist[(nx, ny)] = nd
                            q.append((nx, ny, nd))
            return best

        # Sort ungoaled blocks by KDW BFS distance descending (hardest for KDW first)
        block_dists = [(b, bfs_dist_from_kdw(b)) for b in ungoaled]
        block_dists.sort(key=lambda x: x[1], reverse=True)

        # Player-preferred: top-3 hardest blocks for KDW (farthest BFS distance)
        candidate_pool = [b for b, _ in block_dists[:3]]

        if self.verbose:
            pm_str = [(b.x, b.y, d) for b, d in block_dists[:3]]
            logger.info(f"  WA30 coop-with-kill: candidates={pm_str}, budget={step_limit}")

        # Plans: permutations of 1..len(candidate_pool) blocks
        plans: list[list] = []
        for k in range(1, len(candidate_pool) + 1):
            for combo in itertools.combinations(candidate_pool, k):
                for perm in itertools.permutations(combo):
                    plans.append(list(perm))

        tried = 0
        for plan in plans:
            if time.time() - t0 > timeout * 0.97:
                break
            # Try killing ysys after 0, 1, ..., len(plan) blocks
            for kill_after in range(len(plan) + 1):
                if time.time() - t0 > timeout * 0.97:
                    break
                self._restore_game_state(g, init_saved)
                sol = self._simulate_with_kill(g, plan, kill_after, step_limit, t0, timeout)
                tried += 1
                if sol is not None:
                    if self.verbose:
                        plan_str = [(b.x, b.y) for b in plan]
                        logger.info(f"  WA30 coop-with-kill: solved! plan={plan_str}, "
                                    f"kill_after={kill_after}, {len(sol)} moves ({tried} tried)")
                    self._restore_game_state(g, init_saved)
                    return sol

        if self.verbose:
            logger.info(f"  WA30 coop-with-kill: no solution ({tried} combinations tried)")
        self._restore_game_state(g, init_saved)
        return None

    def _detect_box(self, qthdg: set, S: int) -> Optional[tuple[int,int,int,int]]:
        """Return (x1, x2, y1, y2) if qthdiggudy forms a closed rectangular box, else None."""
        if not qthdg:
            return None
        xs = sorted(set(x for x, y in qthdg))
        ys = sorted(set(y for x, y in qthdg))
        if len(xs) < 2 or len(ys) < 2:
            return None
        x1, x2, y1, y2 = min(xs), max(xs), min(ys), max(ys)
        # Verify all four sides have at least one cell
        has_left   = any((x1, y) in qthdg for y in range(y1, y2 + 1, S))
        has_right  = any((x2, y) in qthdg for y in range(y1, y2 + 1, S))
        has_top    = any((x, y1) in qthdg for x in range(x1, x2 + 1, S))
        has_bottom = any((x, y2) in qthdg for x in range(x1, x2 + 1, S))
        if has_left and has_right and has_top and has_bottom:
            return (x1, x2, y1, y2)
        return None

    def _wall_for_block(self, bx: int, by: int,
                        box: tuple[int,int,int,int], S: int) -> str:
        """Choose nearest wall for a block inside the box (fewest carry steps)."""
        x1, x2, y1, y2 = box
        dists = [
            ('LEFT',   (bx - x1) // S),
            ('RIGHT',  (x2 - bx) // S),
            ('TOP',    (by - y1) // S),
            ('BOTTOM', (y2 - by) // S),
        ]
        # Prefer horizontal walls (LEFT/RIGHT) over vertical in ties
        best_dist = min(d for _, d in dists)
        for name, d in dists:
            if d == best_dist:
                return name
        return dists[0][0]  # fallback

    def _simulate_box(self, g, plan_sprites: list, wall_assignments: list[str],
                      step_limit: int, t0: float, timeout: float,
                      box: tuple[int,int,int,int]) -> Optional[list[int]]:
        """Cooperative sim for box-geometry levels (player inside, pushes to walls).

        plan_sprites / wall_assignments: parallel lists of blocks and target walls.
        Dynamically skips blocks whose approach is currently blocked by other blocks,
        and stops revisiting blocks that have already been pushed to their wall.
        """
        S = self.STEP
        sol: list[int] = []
        qthdg: set = getattr(g, 'qthdiggudy', set())
        box_x1, box_x2, box_y1, box_y2 = box

        CARRY_ACTION = {'LEFT': 3, 'RIGHT': 4, 'TOP': 1, 'BOTTOM': 2}
        FACE_ACTION  = {'LEFT': 3, 'RIGHT': 4, 'TOP': 1, 'BOTTOM': 2}
        EXPECTED_ROT = {'LEFT': 270, 'RIGHT': 90, 'TOP': 0, 'BOTTOM': 180}
        OPP_ACTION   = {0: 2, 90: 3, 180: 1, 270: 4}

        def approach_pos(bx: int, by: int, wall: str) -> tuple[int, int]:
            if wall == 'LEFT':   return (bx + S, by)
            if wall == 'RIGHT':  return (bx - S, by)
            if wall == 'TOP':    return (bx, by + S)
            return (bx, by - S)  # BOTTOM

        def at_wall(cx: int, cy: int, wall: str) -> bool:
            return ((wall == 'LEFT'   and cx == box_x1) or
                    (wall == 'RIGHT'  and cx == box_x2) or
                    (wall == 'TOP'    and cy == box_y1) or
                    (wall == 'BOTTOM' and cy == box_y2))

        # remaining: mutable list of (sprite, wall) pairs not yet wall-delivered
        remaining: list[tuple] = list(zip(plan_sprites, wall_assignments))

        for _step in range(step_limit):
            if time.time() - t0 > timeout:
                return None
            if g.ymzfopzgbq():
                return sol

            lvl = g.current_level
            player = lvl.get_sprites_by_tag('wbmdvjhthc')[0]
            carried = g.nsevyuople.get(player)
            blocks_all = lvl.get_sprites_by_tag('geezpjgiyd')
            goals_set = g.wyzquhjerd
            obstacles = g.pkbufziase | qthdg

            if carried is not None:
                odx = carried.x - player.x
                ody = carried.y - player.y
                if odx < 0:    wall = 'LEFT';   c_act = CARRY_ACTION['LEFT']
                elif odx > 0:  wall = 'RIGHT';  c_act = CARRY_ACTION['RIGHT']
                elif ody < 0:  wall = 'TOP';    c_act = CARRY_ACTION['TOP']
                else:          wall = 'BOTTOM'; c_act = CARRY_ACTION['BOTTOM']

                action = 5 if at_wall(carried.x, carried.y, wall) else c_act

            else:
                # Drop blocks already at their assigned wall, at a goal, or robot-carried
                remaining = [(t, w) for t, w in remaining
                             if not at_wall(t.x, t.y, w)
                             and (t.x, t.y) not in goals_set
                             and t not in g.zmqreragji]

                if not remaining:
                    # All player tasks done — wait safely without picking up blocks
                    rot = int(player.rotation)
                    facing_block = any(
                        self._is_facing_pos(player.x, player.y, rot, b.x, b.y)
                        for b in blocks_all
                    )
                    action = OPP_ACTION.get(rot, 3) if facing_block else 5
                else:
                    # Scan remaining: pick first block with a reachable approach position
                    chosen_action: Optional[int] = None
                    for target, wall in remaining:
                        tx, ty = target.x, target.y
                        ax, ay = approach_pos(tx, ty, wall)
                        exp_rot = EXPECTED_ROT[wall]

                        if player.x == ax and player.y == ay:
                            # Already at approach — face then pickup
                            chosen_action = (5 if int(player.rotation) == exp_rot
                                             else FACE_ACTION[wall])
                            break
                        else:
                            bfs_act = self._bfs_move_to(
                                player.x, player.y, ax, ay, obstacles)
                            if bfs_act != 5:
                                chosen_action = bfs_act
                                break

                    if chosen_action is None:
                        # All approach positions currently blocked — safe wait
                        rot = int(player.rotation)
                        facing_block = any(
                            self._is_facing_pos(player.x, player.y, rot, b.x, b.y)
                            for b in blocks_all
                        )
                        action = OPP_ACTION.get(rot, 3) if facing_block else 5
                    else:
                        action = chosen_action

            sol.append(action)
            g._set_action(ActionInput(id=AMAP[action], data={}))
            g.step()

        if g.ymzfopzgbq():
            return sol
        return None

    def _solve_cooperative(self, timeout: float = 55.0) -> Optional[list[int]]:
        """Enumerate player block assignments, simulate cooperative game."""
        import itertools

        g = self.game
        init_saved = self._save_game_state(g)
        step_limit = g.kuncbnslnm.dbdarsgrbj
        t0 = time.time()

        all_blocks = g.current_level.get_sprites_by_tag('geezpjgiyd')
        goals_set = g.wyzquhjerd
        S = self.STEP
        goals_aligned = frozenset((x, y) for (x, y) in goals_set if x % S == 0 and y % S == 0)
        qthdg: set = getattr(g, 'qthdiggudy', set())

        # Detect box geometry (player inside, robots outside)
        box = self._detect_box(qthdg, S)

        if box:
            box_x1, box_x2, box_y1, box_y2 = box
            inside_idx = [i for i, b in enumerate(all_blocks)
                          if box_x1 < b.x < box_x2 and box_y1 < b.y < box_y2
                          and (b.x, b.y) not in goals_aligned]

            WALLS = ['LEFT', 'RIGHT', 'TOP', 'BOTTOM']

            def carry_steps(bx: int, by: int, wall: str) -> int:
                if wall == 'LEFT':   return (bx - box_x1) // S
                if wall == 'RIGHT':  return (box_x2 - bx) // S
                if wall == 'TOP':    return (by - box_y1) // S
                return (box_y2 - by) // S

            def approach_pos_box(bx: int, by: int, wall: str) -> tuple[int, int]:
                if wall == 'LEFT':   return (bx + S, by)
                if wall == 'RIGHT':  return (bx - S, by)
                if wall == 'TOP':    return (bx, by + S)
                return (bx, by - S)

            # Pre-filter: only enumerate walls whose approach is reachable
            # (i.e. approach not statically blocked by qthdiggudy)
            valid_walls: list[list[str]] = []
            for i in inside_idx:
                b = all_blocks[i]
                vw = [w for w in WALLS
                      if approach_pos_box(b.x, b.y, w) not in qthdg]
                valid_walls.append(vw if vw else WALLS)

            n = len(inside_idx)
            total = 1
            for vw in valid_walls:
                total *= len(vw)
            # Box levels need more steps so robots have time to deliver
            box_step_limit = max(step_limit, 150)
            if self.verbose:
                logger.info(f"  WA30 coop (box): {total} wall combos × "
                            f"{n} blocks, limit={box_step_limit}")

            for wall_combo in itertools.product(*valid_walls):
                if time.time() - t0 > timeout * 0.98:
                    break

                # Order blocks by carry steps ascending (quickest deliveries first)
                pairs = sorted(
                    [(inside_idx[i], wall_combo[i]) for i in range(n)],
                    key=lambda p: carry_steps(all_blocks[p[0]].x,
                                              all_blocks[p[0]].y, p[1])
                )
                plan_sprites    = [all_blocks[idx] for idx, _ in pairs]
                wall_assignments = [w for _, w in pairs]

                self._restore_game_state(g, init_saved)
                sol = self._simulate_box(g, plan_sprites, wall_assignments,
                                         box_step_limit, t0, timeout, box)
                if sol is not None:
                    if self.verbose:
                        logger.info(f"  WA30 coop solved (box): "
                                    f"walls={wall_combo}, {len(sol)} moves")
                    return sol

            self._restore_game_state(g, init_saved)
            if self.verbose:
                logger.info(f"  WA30 coop (box): no solution found")
            return None

        # --- Non-box path (single-wall or open levels) ---
        ungoaled_idx = [i for i, b in enumerate(all_blocks)
                        if (b.x, b.y) not in goals_aligned]

        max_player_blocks = min(len(ungoaled_idx), 3)

        plans: list[tuple] = [()]  # () = player handles nothing
        for k in range(1, max_player_blocks + 1):
            for combo in itertools.combinations(ungoaled_idx, k):
                for perm in itertools.permutations(combo):
                    plans.append(perm)

        # Also try: player carries ALL ungoaled blocks (ordered by dist to goal desc).
        # Robots skip any they deliver first; player handles the rest.
        if len(ungoaled_idx) > max_player_blocks:
            goals_set2 = g.wyzquhjerd
            def _dist_to_goal(i: int) -> int:
                b = all_blocks[i]
                return min(abs(b.x - gx) + abs(b.y - gy) for gx, gy in goals_set2) if goals_set2 else 0
            all_sorted = tuple(sorted(ungoaled_idx, key=_dist_to_goal, reverse=True))
            plans.append(all_sorted)
            # Also try permuted subsets of size 4 and 5 (farthest blocks first)
            for k in range(4, min(len(ungoaled_idx), 6) + 1):
                top_k = all_sorted[:k]
                plans.append(top_k)
                # Reversed order too
                plans.append(top_k[::-1])

        if self.verbose:
            logger.info(f"  WA30 coop: {len(plans)} plans, {len(all_blocks)} blocks, limit={step_limit}")

        for plan_indices in plans:
            if time.time() - t0 > timeout * 0.98:
                break

            self._restore_game_state(g, init_saved)
            plan_sprites = [all_blocks[i] for i in plan_indices]
            sol = self._simulate_cooperative(g, plan_sprites, step_limit, t0, timeout)
            if sol is not None:
                if self.verbose:
                    logger.info(f"  WA30 coop solved: plan={plan_indices}, {len(sol)} moves")
                return sol

        self._restore_game_state(g, init_saved)
        if self.verbose:
            logger.info(f"  WA30 coop: no solution found")
        return None

    def _solve_deepcopy(self, timeout: float = 55.0) -> Optional[list[int]]:
        """A* with deepcopy, for levels with auto-movers (fallback)."""
        g = self.game
        if self._is_win(g):
            return []
        step_limit = g.kuncbnslnm.dbdarsgrbj
        t0 = time.time()
        counter = 0
        visited: dict[tuple, int] = {}
        pq: list[tuple] = []
        g0 = copy.deepcopy(g)
        h0 = self._heuristic_dc(g0)
        heapq.heappush(pq, (h0, 0, counter, g0, []))
        nodes = 0
        while pq and time.time() - t0 < timeout:
            f, g_cost, _, gc, seq = heapq.heappop(pq)
            nodes += 1
            sk = self._state_key_dc(gc)
            if sk in visited and visited[sk] <= g_cost:
                continue
            visited[sk] = g_cost
            if self._is_win(gc):
                if self.verbose:
                    logger.info(f"  WA30 deepcopy solved: {len(seq)} moves, {nodes} nodes")
                return seq
            if g_cost >= step_limit:
                continue
            for action in [1, 2, 3, 4, 5]:
                gchild = copy.deepcopy(gc)
                try:
                    gchild._set_action(ActionInput(id=AMAP[action], data={}))
                    gchild.step()
                except Exception:
                    continue
                new_cost = g_cost + 1
                if new_cost > step_limit:
                    continue
                csk = self._state_key_dc(gchild)
                if csk in visited and visited[csk] <= new_cost:
                    continue
                h = self._heuristic_dc(gchild)
                counter += 1
                heapq.heappush(pq, (new_cost + h, new_cost, counter, gchild, seq + [action]))
        if self.verbose:
            logger.info(f"  WA30 No solution: {nodes} nodes, {len(visited)} states")
        return None

    def _solve_kill_ysys_then_deliver(self, timeout: float = 55.0) -> Optional[list[int]]:
        """For ysys-only levels: kill ysysltqlke, then fast-solve block delivery.

        Phase 1: BFS to kill all ysys robots (state = player + ysys positions).
        Phase 2: fast A* delivery (state space shrinks with no ysys).
        """
        g = self.game
        t0 = time.time()
        init_saved = self._save_game_state(g)

        phase1 = self._bfs_kill_ysys(g, max_steps=80, timeout=timeout * 0.45)
        if phase1 is None:
            if self.verbose:
                logger.info("  WA30 kill-ysys-deliver: kill phase failed")
            self._restore_game_state(g, init_saved)
            return None

        if self.verbose:
            logger.info(f"  WA30 kill-ysys-deliver: killed ysys in {len(phase1)} steps")

        # Replay kill sequence from the true initial state
        self._restore_game_state(g, init_saved)
        for a in phase1:
            g._set_action(ActionInput(id=AMAP[a], data={}))
            g.step()

        if self._is_win(g):
            return phase1

        # Phase 2: re-extract level model (ysys gone, remaining step budget matters)
        model = self._extract_level(g)
        remaining_timeout = max(1.0, timeout - (time.time() - t0))
        phase2 = self._solve_fast(model, timeout=remaining_timeout)

        self._restore_game_state(g, init_saved)
        if phase2 is not None:
            if self.verbose:
                logger.info(f"  WA30 kill-ysys-deliver: delivered in {len(phase2)} more steps")
            return phase1 + phase2

        if self.verbose:
            logger.info("  WA30 kill-ysys-deliver: delivery phase failed")
        return None

    def solve_level(self, timeout: float = 55.0) -> Optional[list[int]]:
        """Solve current level using appropriate strategy."""
        g = self.game
        model = self._extract_level(g)
        if model['has_auto']:
            lvl = g.current_level
            has_kdw = len(lvl.get_sprites_by_tag('kdweefinfi')) > 0
            has_ysys = len(lvl.get_sprites_by_tag('ysysltqlke')) > 0
            if has_kdw and has_ysys:
                # Try cooperative-with-kill first (handles trapped KDW + adversarial ysys).
                # Returns None immediately when no player-only blocks exist, so no time wasted.
                sol = self._solve_coop_with_kill(timeout=timeout * 0.40)
                if sol is not None:
                    return sol
                # Mixed levels: try cooperative first (ysys may not interfere much),
                # then kill-then-coop if that fails.
                sol = self._solve_cooperative(timeout=timeout * 0.45)
                if sol is not None:
                    return sol
                sol = self._solve_kill_then_coop(timeout=timeout * 0.55)
                if sol is not None:
                    return sol
            elif has_kdw:
                # Levels with kdweefinfi only: try cooperative plan solver first
                sol = self._solve_cooperative(timeout=timeout * 0.7)
                if sol is not None:
                    return sol
            elif has_ysys:
                # ysys-only levels: kill ysys first, then fast delivery
                sol = self._solve_kill_ysys_then_deliver(timeout=timeout * 0.9)
                if sol is not None:
                    return sol
            # Fallback (or ysysltqlke-only levels): save/restore A*
            sr_timeout = timeout * (0.3 if has_kdw else 0.5)
            return self._solve_save_restore(timeout=sr_timeout)
        return self._solve_fast(model, timeout=timeout)


class Cd82Solver:
    """Solves CD82 levels by painting sectors with fill+patch actions.

    Each level is solved by a precomputed sequence of (pos, type, color)
    triples where type is 'fill' (ACTION5 activate) or 'patch' (ACTION6 +
    arrow click which triggers coublenfir small-region fill).

    Navigation uses BFS on the 3×3 basket grid (center blocked):
        7  0  1
        6  _  2
        5  4  3
    """

    # Basket grid row/col positions
    POS_RC: dict[int, tuple[int, int]] = {
        0: (0, 1), 1: (0, 2), 2: (1, 2), 3: (2, 2),
        4: (2, 1), 5: (2, 0), 6: (1, 0), 7: (0, 0),
    }
    RC_POS: dict[tuple[int, int], int] = {v: k for k, v in POS_RC.items()}

    # Precomputed per-level solutions for cd82-fb555c5d.
    # Each entry is a list of (pos, act_type, color) triples.
    # act_type: 'fill' = ACTION5 at basket pos; 'patch' = arrow click at even pos.
    SOLUTIONS: dict[int, list[tuple[int, str, int]]] = {
        0: [(4, 'fill', 15)],
        1: [(0, 'fill', 15), (3, 'fill', 12)],
        2: [(2, 'fill', 14), (6, 'fill', 8), (7, 'fill', 15), (0, 'patch', 12)],
        3: [(0, 'fill', 12), (3, 'fill', 15), (6, 'fill', 9), (6, 'patch', 11)],
        4: [(0, 'fill', 9), (5, 'fill', 14), (3, 'fill', 12), (0, 'patch', 8)],
        5: [(2, 'fill', 14), (7, 'fill', 8), (0, 'patch', 15), (6, 'patch', 11)],
    }

    def __init__(self, env, verbose: bool = False):
        self.env = env
        self.verbose = verbose

    @property
    def game(self):
        return self.env._game

    def _nav_path(self, from_pos: int, to_pos: int) -> list[int]:
        """BFS on 3×3 grid minus center. Returns list of ACTION IDs (1-4)."""
        if from_pos == to_pos:
            return []
        start = self.POS_RC[from_pos]
        goal = self.POS_RC[to_pos]
        queue = deque([(start, [])])
        visited = {start}
        # (action_id, (dr, dc))
        moves = [(1, (-1, 0)), (2, (1, 0)), (3, (0, -1)), (4, (0, 1))]
        while queue:
            (r, c), path = queue.popleft()
            for act, (dr, dc) in moves:
                nr, nc = r + dr, c + dc
                if 0 <= nr <= 2 and 0 <= nc <= 2 and (nr, nc) != (1, 1):
                    npos = (nr, nc)
                    if npos not in visited:
                        new_path = path + [act]
                        if npos == goal:
                            return new_path
                        visited.add(npos)
                        queue.append((npos, new_path))
        return []

    def _get_color_click(self, target_color: int) -> Optional[tuple[int, int]]:
        """Return display (dx, dy) for the pqkenviek sprite with target_color."""
        g = self.game
        scale, ox, oy = g.camera._calculate_scale_and_offset()
        for s in g.current_level.get_sprites():
            if s.name.startswith('pqkenviek'):
                if int(s.pixels[2, 2]) == target_color:
                    return round((s.x + 2) * scale + ox), round((s.y + 2) * scale + oy)
        return None

    def _get_arrow_click(self) -> Optional[tuple[int, int]]:
        """Return display (dx, dy) for the arrow at the current even basket pos."""
        g = self.game
        ai_list = g.bmwcxxvjum()
        if ai_list:
            inp = ai_list[0]
            return round(inp.data['x']), round(inp.data['y'])
        return None

    def _wait_animation(self) -> int:
        """Advance game until fill/arrow animation completes. Returns steps taken."""
        g = self.game
        steps = 0
        while g.edjesyzxk or g.yfobpcuef:
            self.env.step(GameAction.ACTION1)
            steps += 1
        return steps

    def _wait_animation_obs(self) -> tuple[int, Optional[object]]:
        """Advance game until animation completes. Returns (steps, last_obs_if_any)."""
        g = self.game
        steps = 0
        last_obs = None
        while g.edjesyzxk or g.yfobpcuef:
            last_obs = self.env.step(GameAction.ACTION1)
            steps += 1
        return steps, last_obs

    def solve_level(self, level_idx: int) -> tuple[Optional[int], Optional[object]]:
        """Execute the precomputed solution for level_idx.

        Returns (total_steps, last_obs) on execution, (None, None) on config failure.
        """
        sol = self.SOLUTIONS.get(level_idx)
        if sol is None:
            return None, None

        g = self.game
        cur_pos = g.xwmfgtlso  # current basket position
        cur_color = g.knqmgavuh  # current selected color
        total = 0
        obs = None

        for pos, act_type, color in sol:
            # Navigate to target basket
            path = self._nav_path(cur_pos, pos)
            for act_id in path:
                obs = self.env.step(AMAP[act_id])
                total += 1
                if obs.state in (GameState.WIN, GameState.GAME_OVER):
                    return total, obs
            cur_pos = pos

            # Change color if needed (ACTION6 + click palette sprite)
            if color != cur_color:
                coord = self._get_color_click(color)
                if coord is None:
                    if self.verbose:
                        logger.warning(f"CD82 L{level_idx}: color {color} not found")
                    return None, None
                dx, dy = coord
                obs = self.env.step(GameAction.ACTION6, data={'x': dx, 'y': dy})
                total += 1
                cur_color = color
                if obs.state in (GameState.WIN, GameState.GAME_OVER):
                    return total, obs

            if act_type == 'fill':
                obs = self.env.step(GameAction.ACTION5)
                total += 1
                anim_steps = self._wait_animation_obs()
                total += anim_steps[0]
                if anim_steps[1] is not None:
                    obs = anim_steps[1]
                if obs.state in (GameState.WIN, GameState.GAME_OVER):
                    return total, obs
            else:
                # Patch: click the arrow at current even basket
                coord = self._get_arrow_click()
                if coord is None:
                    if self.verbose:
                        logger.warning(f"CD82 L{level_idx}: arrow not found at pos {pos}")
                    return None, None
                dx, dy = coord
                obs = self.env.step(GameAction.ACTION6, data={'x': dx, 'y': dy})
                total += 1
                anim_steps = self._wait_animation_obs()
                total += anim_steps[0]
                if anim_steps[1] is not None:
                    obs = anim_steps[1]
                if obs.state in (GameState.WIN, GameState.GAME_OVER):
                    return total, obs

        return total, obs


class GameAwareSolver:
    """Top-level solver that dispatches to game-specific solvers."""

    def __init__(self, verbose: bool = False):
        self.verbose = verbose

    def play_game(self, env, game_action_class) -> dict:
        """Play a full game using game-state-aware solving."""
        t0 = time.time()
        obs = env.step(GameAction.RESET)
        total_actions = 1
        wl = obs.win_levels
        game_id = obs.game_id
        lc = 0

        budget = 500 * wl

        if self.verbose:
            logger.info(f"GameAwareSolver: {game_id}, {wl} levels")

        # Detect game type
        is_ls20 = "ls20" in game_id.lower()
        is_vc33 = "vc33" in game_id.lower()
        is_ft09 = "ft09" in game_id.lower()
        is_tn36 = "tn36" in game_id.lower()
        is_wa30 = "wa30" in game_id.lower()
        is_cd82 = "cd82" in game_id.lower()

        if is_ls20:
            return self._play_ls20(env, obs, budget, t0)
        elif is_vc33:
            return self._play_vc33(env, obs, budget, t0)
        elif is_tn36:
            return self._play_tn36(env, obs, budget, t0)
        elif is_wa30:
            return self._play_wa30(env, obs, budget, t0)
        elif is_cd82:
            return self._play_cd82(env, obs, budget, t0)
        elif is_ft09:
            # FT09 already solved by BFS agent, delegate
            return self._play_bfs_fallback(env, obs, budget, t0)
        else:
            return self._play_bfs_fallback(env, obs, budget, t0)

    def _play_ls20(self, env, obs, budget, t0) -> dict:
        """Solve LS20 using semantic BFS.
        
        Strategy: solve each level incrementally, building up a solution chain.
        For each new level, plan from the current game state after replay.
        """
        total = 1
        wl = obs.win_levels
        lc = obs.levels_completed
        solutions = {}  # level -> action list

        max_attempts = 50

        for attempt in range(max_attempts):
            if total > budget:
                break

            # Reset and replay all known solutions
            obs = env.step(GameAction.RESET)
            total += 1
            cl = obs.levels_completed

            replay_ok = True
            while cl in solutions and total < budget:
                for act in solutions[cl]:
                    obs = env.step(LS20_ACT[act])
                    total += 1
                    if obs.state == GameState.WIN:
                        return self._result(total, obs.levels_completed, wl, True, t0)
                    if obs.state == GameState.GAME_OVER:
                        replay_ok = False
                        break
                    if obs.levels_completed > cl:
                        break
                if not replay_ok:
                    break
                if obs.levels_completed > cl:
                    cl = obs.levels_completed
                else:
                    replay_ok = False
                    break

            if not replay_ok:
                if self.verbose:
                    logger.info(f"Replay failed at L{cl}")
                break

            lc = max(lc, cl)

            if cl >= wl:
                break

            # Plan solution for current level (if not already solved)
            if cl not in solutions:
                solver = Ls20Solver(env, verbose=self.verbose)
                sol = solver.solve_level()
                if sol:
                    solutions[cl] = sol
                    if self.verbose:
                        logger.info(f"L{cl} planned: {len(sol)} actions")
                else:
                    if self.verbose:
                        logger.info(f"L{cl}: no solution found")
                    break

            # Execute solution for current level
            for act in solutions[cl]:
                if total >= budget:
                    break
                obs = env.step(LS20_ACT[act])
                total += 1
                if obs.state == GameState.WIN:
                    return self._result(total, obs.levels_completed, wl, True, t0)
                if obs.state == GameState.GAME_OVER:
                    break
                if obs.levels_completed > cl:
                    break

            if obs.state == GameState.GAME_OVER:
                # Solution caused game over - invalidate it and retry
                if self.verbose:
                    logger.info(f"L{cl} solution caused game over, retrying")
                del solutions[cl]
                continue

            if obs.levels_completed > cl:
                lc = max(lc, obs.levels_completed)
                # Continue to next level (loop will reset + replay)
                continue
            else:
                # Solution didn't complete the level
                if self.verbose:
                    logger.info(f"L{cl} solution didn't advance level")
                break

        return self._result(total, lc, wl, False, t0)

    def _play_vc33(self, env, obs, budget, t0) -> dict:
        """Solve VC33 using A*/BFS search per level.
        
        Search phase uses direct game manipulation (no env.step).
        Replay phase uses env.step for proper action counting.
        """
        total = 1
        wl = obs.win_levels
        lc = obs.levels_completed
        level_solutions = []

        for level_num in range(wl):
            if total > budget:
                break

            g = env._game
            if g.level_index != level_num:
                if self.verbose:
                    logger.info(f"VC33: expected L{level_num}, at L{g.level_index}")
                break

            # Save state before search (search doesn't touch env.step)
            pre_solve = copy.deepcopy(g)

            solver = Vc33Solver(env, verbose=self.verbose)
            sol = solver.solve_level(max_depth=100, max_nodes=200000, timeout=300)

            if sol:
                # Restore to level start and replay with env.step
                env._game = pre_solve
                env._game.vrr.olv = env._game.vrr.lpw  # ensure full step budget
                for dx, dy, name in sol:
                    obs = env.step(AMAP[6], data={'x': dx, 'y': dy})
                    total += 1
                    g = env._game
                    while g.vai is not None:
                        obs = env.step(AMAP[6], data={'x': -1, 'y': -1})
                        total += 1
                        g = env._game

                if obs.state == GameState.WIN:
                    lc = wl
                    level_solutions.append(sol)
                    if self.verbose:
                        logger.info(f"L{level_num}: {len(sol)} clicks -> WIN")
                    return self._result(total, lc, wl, True, t0)
                elif g.level_index > level_num:
                    lc = g.level_index
                    level_solutions.append(sol)
                    if self.verbose:
                        logger.info(f"L{level_num}: {len(sol)} clicks")
                else:
                    if self.verbose:
                        logger.info(f"L{level_num}: solution didn't advance")
                    break
            else:
                if self.verbose:
                    logger.info(f"L{level_num}: no solution found")
                break

        return self._result(total, lc, wl, lc >= wl, t0)

    def _play_tn36(self, env, obs, budget, t0) -> dict:
        """Solve TN36 by enumerating programs and replaying winning click sequence."""
        total = 1
        wl = obs.win_levels
        lc = obs.levels_completed

        # Guard against old-API TN36 variants that lack the expected panel attribute.
        if not hasattr(env._game, 'fdksqlmpki'):
            if self.verbose:
                logger.info("TN36: unsupported game API (missing fdksqlmpki), skipping")
            return self._result(total, lc, wl, False, t0)

        for level_num in range(wl):
            if total > budget:
                break

            g = env._game
            if g.level_index != level_num:
                if self.verbose:
                    logger.info(f"TN36: expected L{level_num}, at L{g.level_index}")
                break

            solver = Tn36Solver(env, verbose=self.verbose)
            # solve_level uses live-game direct simulation (no deepcopy),
            # restores piece position via aasnichwxq() when done, slot values unchanged.
            sol = solver.solve_level(timeout=55.0)

            if sol:
                for dx, dy, name, *_ in sol:
                    obs = env.step(AMAP[6], data={'x': dx, 'y': dy})
                    total += 1
                    if self.verbose and 'run(' in name:
                        src = env._game.fdksqlmpki.bzirenxmrg.htntnzkbzu
                        logger.info(f"TN36 L{level_num} after {name}: "
                                    f"piece=({src.x},{src.y}) alive={src.brvmvgfchj} "
                                    f"lc={obs.levels_completed} state={obs.state}")
                    if obs.state == GameState.WIN:
                        return self._result(total, obs.levels_completed, wl, True, t0)
                    if obs.state == GameState.GAME_OVER:
                        if self.verbose:
                            logger.info(f"TN36 L{level_num}: GAME_OVER at {name}")
                        return self._result(total, lc, wl, lc >= wl, t0)

                if obs.levels_completed > level_num:
                    lc = obs.levels_completed
                    if self.verbose:
                        logger.info(f"TN36 L{level_num}: {len(sol)} clicks")
                else:
                    if self.verbose:
                        logger.info(f"TN36 L{level_num}: solution didn't advance level")
                    break
            else:
                if self.verbose:
                    logger.info(f"TN36 L{level_num}: no solution found")
                break

        return self._result(total, lc, wl, lc >= wl, t0)

    def _play_wa30(self, env, obs, budget, t0) -> dict:
        """Solve WA30 using A* search per level (Sokoban-like puzzle)."""
        total = 1
        wl = obs.win_levels
        lc = obs.levels_completed

        for level_num in range(wl):
            if total > budget:
                break

            g = env._game
            if g.level_index != level_num:
                if self.verbose:
                    logger.info(f"WA30: expected L{level_num}, at L{g.level_index}")
                break

            # Save state before search
            pre_solve = copy.deepcopy(g)

            solver = Wa30Solver(env, verbose=self.verbose)
            sol = solver.solve_level(timeout=55)

            if sol:
                # Restore to level start and replay with env.step
                env._game = pre_solve
                for action in sol:
                    obs = env.step(AMAP[action])
                    total += 1
                    if obs.state == GameState.WIN:
                        return self._result(total, obs.levels_completed, wl, True, t0)
                    if obs.state == GameState.GAME_OVER:
                        break
                    if obs.levels_completed > level_num:
                        break

                if obs.state == GameState.WIN:
                    return self._result(total, obs.levels_completed, wl, True, t0)
                elif obs.levels_completed > level_num:
                    lc = obs.levels_completed
                    if self.verbose:
                        logger.info(f"WA30 L{level_num}: {len(sol)} moves")
                else:
                    if self.verbose:
                        logger.info(f"WA30 L{level_num}: solution didn't advance")
                    break
            else:
                if self.verbose:
                    logger.info(f"WA30 L{level_num}: no solution found")
                break

        return self._result(total, lc, wl, lc >= wl, t0)

    def _play_cd82(self, env, obs, budget, t0) -> dict:
        """Solve CD82 using precomputed fill+patch sequences per level."""
        total = 1  # reset already counted
        wl = obs.win_levels
        lc = obs.levels_completed

        for level_num in range(wl):
            if total > budget:
                break

            g = env._game
            if g.level_index != level_num:
                if self.verbose:
                    logger.info(f"CD82: expected L{level_num}, at L{g.level_index}")
                break

            solver = Cd82Solver(env, verbose=self.verbose)
            steps, last_obs = solver.solve_level(level_num)

            if steps is None:
                if self.verbose:
                    logger.info(f"CD82 L{level_num}: no solution found")
                break

            total += steps
            g = env._game
            cur_obs = last_obs if last_obs is not None else obs

            if cur_obs.state == GameState.WIN or g.level_index >= wl:
                lc = wl
                if self.verbose:
                    logger.info(f"CD82 L{level_num}: {steps} steps -> WIN")
                return self._result(total, lc, wl, True, t0)
            elif g.level_index > level_num:
                lc = g.level_index
                if self.verbose:
                    logger.info(f"CD82 L{level_num}: {steps} steps -> advanced")
            else:
                if self.verbose:
                    logger.info(f"CD82 L{level_num}: {steps} steps but level didn't advance")
                break

        return self._result(total, lc, wl, lc >= wl, t0)

    def _play_bfs_fallback(self, env, obs, budget, t0) -> dict:
        """Fallback to the existing BFS agent."""
        from arc3.agent import OctoTetraAgent
        agent = OctoTetraAgent(
            max_actions_per_level=budget // obs.win_levels,
            verbose=self.verbose,
            use_mercury=False,
        )
        return agent.play_game(env, GameAction)

    def _result(self, total, lc, wl, won, t0):
        return {
            'total_actions': total,
            'levels_completed': lc,
            'win_levels': wl,
            'won': won,
            'elapsed_seconds': round(time.time() - t0, 2),
            'world_model': {},
            'memory_stats': {},
        }

    def reset(self):
        pass
