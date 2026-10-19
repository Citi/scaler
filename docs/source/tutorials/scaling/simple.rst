Simple Engine
=============

``simple`` requires a semicolon-delimited ``policy_content`` string with exactly two keys:

* ``allocate``: ``even_load`` or ``capability``
* ``scaling``: ``static``, ``vanilla``, or ``capability``

Quick Start (copy/paste)
------------------------

The example below starts a scheduler and one native worker manager using ``vanilla`` scaling.

.. tabs::

    .. group-tab:: config.toml

        .. code-block:: toml

            [object_storage_server]
            bind_address = "tcp://127.0.0.1:8517"

            [scheduler]
            bind_address = "tcp://127.0.0.1:8516"
            object_storage_address = "tcp://127.0.0.1:8517"
            policy_engine_type = "simple"
            policy_content = "allocate=even_load; scaling=vanilla"

            [[worker_manager]]
            type = "baremetal_native"
            scheduler_address = "tcp://127.0.0.1:8516"
            object_storage_address = "tcp://127.0.0.1:8517"
            worker_manager_id = "NAT|default"
            max_task_concurrency = 8

        Run command:

        .. code-block:: bash

            scaler config.toml

    .. group-tab:: command line

        .. code-block:: bash

            scaler_object_storage_server tcp://127.0.0.1:8517 &
            scaler_scheduler tcp://127.0.0.1:8516 \
                --object-storage-address tcp://127.0.0.1:8517 \
                --policy-engine-type simple \
                --policy-content "allocate=even_load; scaling=vanilla" &
            scaler_worker_manager baremetal_native tcp://127.0.0.1:8516 \
                --object-storage-address tcp://127.0.0.1:8517 \
                --worker-manager-id NAT|default \
                --max-task-concurrency 8

Other quick policy strings for ``simple``:

.. tabs::

    .. group-tab:: config.toml

        .. code-block:: toml

            # Fixed capacity: every worker manager runs its advertised maximum
            policy_engine_type = "simple"
            policy_content = "allocate=even_load; scaling=static"

            # Capability-aware autoscaling (recommended pair)
            policy_engine_type = "simple"
            policy_content = "allocate=capability; scaling=capability"

    .. group-tab:: command line

        .. code-block:: text

            # Fixed capacity: every worker manager runs its advertised maximum
            --policy-engine-type simple --policy-content "allocate=even_load; scaling=static"

            # Capability-aware autoscaling (recommended pair)
            --policy-engine-type simple --policy-content "allocate=capability; scaling=capability"

Allocation
----------

The ``allocate`` option controls how tasks are assigned to available workers.

* ``allocate=even_load``

  * Spreads tasks across workers evenly.
  * Best for homogeneous workers where any worker can run any task.
  * Commonly paired with ``scaling=vanilla``.

* ``allocate=capability``

  * Routes tasks to workers whose capabilities match task requirements.
  * Best for heterogeneous clusters (for example CPU-only + GPU workers).
  * Should be paired with ``scaling=capability`` so scale-up requests are also capability-aware.

Capability routing example:

.. literalinclude:: ../../../../examples/task_capabilities.py
   :language: python

Scaling
-------

The ``scaling`` option controls how worker capacity grows or shrinks.

* ``scaling=static``, ``scaling=static:N``, or ``scaling=static[<counts>]``

  * Requests a fixed task concurrency from each worker manager, whatever the load.
  * ``static`` requests the maximum task concurrency each worker manager advertises.
  * ``static:N`` requests ``N``, capped at that maximum. ``static:0`` stops every worker.
  * ``static[<counts>]`` requests a count per worker manager, see `Static counts`_.
  * Only ``static`` takes an argument.

* ``scaling=vanilla`` or ``scaling=vanilla[<bounds>]``

  * General autoscaling for homogeneous clusters.
  * Scale up when ``tasks / workers > 10``.
  * Scale down when ``tasks / workers < 1``.
  * ``workers`` counts serving workers only: a draining worker takes no new task.
  * The optional bounds keep each named worker manager within a range, see `Vanilla bounds`_.

* ``scaling=capability``

  * Capability-aware autoscaling for heterogeneous clusters.
  * Groups demand by capability and scales per capability group.
  * Scale up when ``tasks / capable_workers > 5``.
  * Scale down when ``tasks / capable_workers < 0.5``.

Static counts
-------------

``static`` takes an optional list of counts, one entry per worker manager, separated by ``,``:

.. code-block:: text

    allocate=even_load; scaling=static[native-local:8, ecs-burst:0]

* An entry is ``worker_manager_id:task_concurrency``.
* Each count is capped at the worker manager's heartbeat ``max_task_concurrency``.
* A worker manager without an entry gets its heartbeat's ``max_task_concurrency``, as with plain ``static``.
* ``static:N`` and a list of counts cannot be combined.
* A ``worker_manager_id`` in the counts cannot contain ``:``, ``,``, ``[``, ``]``, or ``;``.
* A negative count or a repeated ``worker_manager_id`` is refused at startup.

Vanilla bounds
--------------

``vanilla`` takes an optional list of bounds, one entry per worker manager, separated by ``,``:

.. code-block:: text

    allocate=even_load; scaling=vanilla[native-local:8:8, ecs-burst:100]

* An entry is ``worker_manager_id:max_task_concurrency[:min_task_concurrency]``.
* The effective cap is ``min(max_task_concurrency, heartbeat.max_task_concurrency)``; leave it empty to keep only the heartbeat's: ``warm::2``.
* The worker manager never gets fewer than its floor, clamped to the effective cap, even with no tasks.
* A worker manager without an entry ranges from ``0`` to its heartbeat's ``max_task_concurrency``.
* A ``worker_manager_id`` in the bounds cannot contain ``:``, ``,``, ``[``, ``]``, or ``;``.
* A floor above its cap, a negative count, or a repeated ``worker_manager_id`` is refused at startup.

An entry whose floor equals its cap holds a fixed pool next to worker managers that scale.
In the example, ``native-local`` always runs 8 workers, and ``ecs-burst`` scales with the load.
When the load shrinks, ``vanilla`` counts the workers held at other managers' floors as supply.
So a few tasks over an idle fixed pool do not start a worker on ``ecs-burst``.

Notes:

* ``policy_content`` must contain exactly ``allocate`` and ``scaling`` keys.
* The desired worker count emitted in ``setDesiredTaskConcurrency`` is capped by each manager heartbeat's ``max_task_concurrency``.
* Threshold values are currently fixed in code.
